// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv/warp/warp_gemm_dispatcher.hpp"

namespace ck_tile {

template <typename Problem>
struct BlockGemmMmacTNAsmemBSmemCregWaspV1
{
    static constexpr index_t MPerWG    = Problem::MPerWG;
    static constexpr index_t NPerWG    = Problem::NPerWG;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t MWarpsPerWG = Problem::MWarpsPerWG;
    static constexpr index_t NWarpsPerWG = Problem::NWarpsPerWG;

    static constexpr index_t MWarpIterPerWG = Problem::MWarpIterPerWG;
    static constexpr index_t NWarpIterPerWG = Problem::NWarpIterPerWG;

    static constexpr index_t MmmacIter = Problem::MmmacIter;
    static constexpr index_t NmmacIter = Problem::NmmacIter;

    static constexpr index_t MPerMmac = Problem::MPerMmac;
    static constexpr index_t NPerMmac = Problem::NPerMmac;

    static constexpr index_t MmmacInterleave = Problem::MmmacInterleave;
    static constexpr index_t NmmacInterleave = Problem::NmmacInterleave;

    static constexpr index_t KIter =
        KPerBlock / conv::WarpGemmMmacDispatcher<typename Problem::InDataType,
                                                 typename Problem::WeiDataType,
                                                 typename Problem::AccDataType,
                                                 MmmacIter,
                                                 NmmacIter,
                                                 MPerMmac,
                                                 NPerMmac,
                                                 MmmacInterleave,
                                                 NmmacInterleave,
                                                 1,
                                                 Problem::TransposeC>::kK;

    using WarpGemm = typename conv::WarpGemmMmacDispatcher<typename Problem::InDataType,
                                                           typename Problem::WeiDataType,
                                                           typename Problem::AccDataType,
                                                           MmmacIter,
                                                           NmmacIter,
                                                           MPerMmac,
                                                           NPerMmac,
                                                           MmmacInterleave,
                                                           NmmacInterleave,
                                                           KIter,
                                                           Problem::TransposeC>;

    static constexpr index_t MPerBlockPerIter = MWarpsPerWG * WarpGemm::kM;
    static constexpr index_t NPerBlockPerIter = NWarpsPerWG * WarpGemm::kN;
    static constexpr index_t KPerBlockPerIter = WarpGemm::kK;

    static constexpr index_t KWarpIter = KPerBlock / WarpGemm::kK;

    CK_TILE_HOST_DEVICE constexpr BlockGemmMmacTNAsmemBSmemCregWaspV1()
    {
        static_assert(Problem::WGSize == MWarpsPerWG * NWarpsPerWG * get_warp_size(),
                      "WGSize != MWarpsPerWG * NWarpsPerWG * get_warp_size()");

        static_assert(MPerWG % (MWarpIterPerWG * MmmacIter * MPerMmac * MmmacInterleave) == 0,
                      "wrong!");

        static_assert(NPerWG % (NWarpIterPerWG * NmmacIter * NPerMmac * NmmacInterleave) == 0,
                      "wrong!");
    }

    template <typename ALdsWindow>
    CK_TILE_DEVICE auto LdsLoadIn(const ALdsWindow& a_lds_window) const
    {
        const index_t warp_id_m = ck_tile::get_sub_warp_id(Problem::SubWGSize) / NWarpsPerWG;

        auto warp_window = make_tile_window(
            a_lds_window.get_bottom_tensor_view(),
            make_tuple(number<WarpGemm::kM>{}, number<WarpGemm::kK>{}),
            a_lds_window.get_window_origin() + multi_index<2>{warp_id_m * WarpGemm::kM, 0},
            make_static_tile_distribution(typename WarpGemm::AWarpDstrEncoding{}));

        // warp tensors for MWarpIterPerWG * KWarpIter iterations
        statically_indexed_array<
            statically_indexed_array<
                decltype(load_tile(warp_window, bool_constant<true>{}, bool_constant<true>{})),
                KWarpIter>,
            MWarpIterPerWG>
            warp_tensors;

        using SFC =
            space_filling_curve<sequence<MWarpIterPerWG, KWarpIter>, sequence<0, 1>, sequence<1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto i) {
            constexpr auto idx = SFC::get_index(i);

            constexpr auto m_warp_iter = idx.at(number<0>{});
            constexpr auto k_warp_iter = idx.at(number<1>{});

            warp_tensors(m_warp_iter)(k_warp_iter) =
                load_tile(warp_window, bool_constant<true>{}, bool_constant<true>{});

            if constexpr(i != num_access - 1)
            {
                constexpr auto step = SFC::get_forward_step(i);
                move_tile_window(warp_window,
                                 {step.at(number<0>{}) * MPerBlockPerIter,
                                  step.at(number<1>{}) * KPerBlockPerIter});
            }
        });

        return warp_tensors;
    }

    template <typename BLdsWindow>
    CK_TILE_DEVICE auto LdsLoadWei(const BLdsWindow& b_lds_window) const
    {
        const index_t warp_id_n = ck_tile::get_sub_warp_id(Problem::SubWGSize) % NWarpsPerWG;

        auto warp_window = make_tile_window(
            b_lds_window.get_bottom_tensor_view(),
            make_tuple(number<WarpGemm::kN>{}, number<WarpGemm::kK>{}),
            b_lds_window.get_window_origin() + multi_index<2>{warp_id_n * WarpGemm::kN, 0},
            make_static_tile_distribution(typename WarpGemm::BWarpDstrEncoding{}));

        // warp tensors for MWarpIterPerWG * KWarpIter iterations
        statically_indexed_array<
            statically_indexed_array<
                decltype(load_tile(warp_window, bool_constant<true>{}, bool_constant<true>{})),
                KWarpIter>,
            NWarpIterPerWG>
            warp_tensors;

        using SFC =
            space_filling_curve<sequence<NWarpIterPerWG, KWarpIter>, sequence<0, 1>, sequence<1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto i) {
            constexpr auto idx = SFC::get_index(i);

            constexpr auto n_warp_iter = idx.at(number<0>{});
            constexpr auto k_warp_iter = idx.at(number<1>{});

            warp_tensors(n_warp_iter)(k_warp_iter) =
                load_tile(warp_window, bool_constant<true>{}, bool_constant<true>{});

            if constexpr(i != num_access - 1)
            {
                constexpr auto step = SFC::get_forward_step(i);
                move_tile_window(warp_window,
                                 {step.at(number<0>{}) * NPerBlockPerIter,
                                  step.at(number<1>{}) * KPerBlockPerIter});
            }
        });

        return warp_tensors;
    }

    template <typename CBlockTensor, typename AWarpTensors, typename BWarpTensors>
    CK_TILE_DEVICE void operator()(CBlockTensor& c_block_tensor,
                                   const AWarpTensors& a_warp_tensors,
                                   const BWarpTensors& b_warp_tensors) const
    {
        using SFC = space_filling_curve<sequence<MWarpIterPerWG, NWarpIterPerWG, KWarpIter>,
                                        sequence<0, 1, 2>,
                                        sequence<1, 1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SFC::get_index(access_id);

            constexpr auto m_warp_iter = idx.at(number<0>{});
            constexpr auto n_warp_iter = idx.at(number<1>{});
            constexpr auto k_warp_iter = idx.at(number<2>{});

            using CWarpDstr   = typename WarpGemm::CWarpDstr;
            using CWarpTensor = typename WarpGemm::CWarpTensor;

            constexpr auto c_warp_y_lengths =
                to_sequence(CWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto c_warp_y_index_zeros = uniform_sequence_gen_t<CWarpDstr::NDimY, 0>{};

            CWarpTensor c_warp_tensor;

            c_warp_tensor.get_thread_buffer() = c_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, c_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, c_warp_y_lengths));

            // warp GEMM
            WarpGemm{}(c_warp_tensor,
                       a_warp_tensors[m_warp_iter][k_warp_iter],
                       b_warp_tensors[n_warp_iter][k_warp_iter]);

            // write C warp tensor into C block tensor
            c_block_tensor.set_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, c_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, c_warp_y_lengths),
                c_warp_tensor.get_thread_buffer());
        });
    }

    CK_TILE_DEVICE static auto MakeOutBlockTile()
    {
        // wave distribution encoding
        constexpr auto c_block_outer_dstr_encoding = tile_distribution_encoding<
            sequence<>,
            tuple<sequence<MWarpIterPerWG, MWarpsPerWG>, sequence<NWarpIterPerWG, NWarpsPerWG>>,
            tuple<sequence<1, 2>>,
            tuple<sequence<1, 1>>,
            sequence<1, 2>,
            sequence<0, 0>>{};

        // combine wave distribution and lane distribution
        constexpr auto c_block_dstr_encoding = detail::make_embed_tile_distribution_encoding(
            c_block_outer_dstr_encoding, typename WarpGemm::CWarpDstrEncoding{});

        constexpr auto c_block_dstr = make_static_tile_distribution(
            c_block_dstr_encoding, bool_constant<true>{}, number<Problem::SubWGSize>{});

        return make_static_distributed_tensor<typename Problem::AccDataType>(c_block_dstr);
    }
};

} // namespace ck_tile
