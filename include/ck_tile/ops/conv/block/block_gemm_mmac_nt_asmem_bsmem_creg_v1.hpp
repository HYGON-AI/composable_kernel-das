// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv/warp/warp_gemm_dispatcher.hpp"
#include "ck_tile/ops/gemm/warp/warp_dsreadm_dispatcher.hpp"

namespace ck_tile {

template <typename Problem>
struct BlockGemmMmacNTAsmemBSmemCregV1
{
    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t MWarps = Problem::MWarps;
    static constexpr index_t NWarps = Problem::NWarps;

    static constexpr index_t MWarpIter = Problem::MWarpIter;
    static constexpr index_t NWarpIter = Problem::NWarpIter;

    static constexpr index_t MmmacIter = Problem::MmmacIter;
    static constexpr index_t NmmacIter = Problem::NmmacIter;

    static constexpr index_t MPermmac = Problem::MPermmac;
    static constexpr index_t NPermmac = Problem::NPermmac;

    static constexpr index_t MmmacInterleave = Problem::MmmacInterleave;
    static constexpr index_t NmmacInterleave = Problem::NmmacInterleave;

    using WG = typename conv::WarpGemmMmacDispatcher<typename Problem::ADataType,
                                                     typename Problem::BDataType,
                                                     typename Problem::AccDataType,
                                                     MmmacIter,
                                                     NmmacIter,
                                                     MPermmac,
                                                     NPermmac,
                                                     MmmacInterleave,
                                                     NmmacInterleave,
                                                     1,
                                                     Problem::TransposeC>;

    using ADsreadm =
        WarpDsreadmDispatcher<typename Problem::ADataType, MmmacIter, MPermmac, MmmacInterleave>;

    using BDsreadm =
        WarpDsreadmDispatcher<typename Problem::BDataType, NmmacIter, NPermmac, NmmacInterleave>;

    static constexpr index_t MPerBlockPerIter = MWarps * WG::kM;
    static constexpr index_t NPerBlockPerIter = NWarps * WG::kN;
    static constexpr index_t KPerBlockPerIter = WG::kK;

    static constexpr index_t KWarpIter  = KPerBlock / WG::kK;
    static constexpr index_t KPerThread = KWarpIter * WG::WarpGemmAttribute::Impl::kABKPerLane;

    CK_TILE_HOST_DEVICE constexpr BlockGemmMmacNTAsmemBSmemCregV1()
    {
        static_assert(Problem::BlockSize == MWarps * NWarps * get_warp_size(),
                      "BlockSize != MWarps * NWarps * get_warp_size()");

        static_assert(MPerBlock % (MWarpIter * MmmacIter * MPermmac * MmmacInterleave) == 0,
                      "wrong!");

        static_assert(NPerBlock % (NWarpIter * NmmacIter * NPermmac * NmmacInterleave) == 0,
                      "wrong!");
    }

    template <typename ALdsWindow>
    CK_TILE_DEVICE auto LdsLoadA(const ALdsWindow& a_lds_window) const
    {
        const index_t warp_id_m = ck_tile::get_warp_id() / NWarps;

        auto warp_window = make_tile_window(
            a_lds_window.get_bottom_tensor_view(),
            make_tuple(number<WG::kM>{}, number<WG::kK>{}),
            a_lds_window.get_window_origin() + multi_index<2>{warp_id_m * WG::kM, 0},
            make_static_tile_distribution(typename ADsreadm::WarpLoadDstrEncoding{}));

        // warp tensors for MWarpIter * KWarpIter iterations
        statically_indexed_array<
            statically_indexed_array<decltype(load_tile_by_dsreadm(ADsreadm{}, warp_window)),
                                     KWarpIter>,
            MWarpIter>
            warp_tensors;

        using SFC =
            space_filling_curve<sequence<MWarpIter, KWarpIter>, sequence<0, 1>, sequence<1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto i) {
            constexpr auto idx = SFC::get_index(i);

            constexpr auto m_warp_iter = idx.at(number<0>{});
            constexpr auto k_warp_iter = idx.at(number<1>{});

            warp_tensors(m_warp_iter)(k_warp_iter) = load_tile_by_dsreadm(ADsreadm{}, warp_window);

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
    CK_TILE_DEVICE auto LdsLoadB(const BLdsWindow& b_lds_window) const
    {
        const index_t warp_id_n = ck_tile::get_warp_id() % NWarps;

        auto warp_window = make_tile_window(
            b_lds_window.get_bottom_tensor_view(),
            make_tuple(number<WG::kN>{}, number<WG::kK>{}),
            b_lds_window.get_window_origin() + multi_index<2>{warp_id_n * WG::kN, 0},
            make_static_tile_distribution(typename BDsreadm::WarpLoadDstrEncoding{}));

        // warp tensors for MWarpIter * KWarpIter iterations
        statically_indexed_array<
            statically_indexed_array<decltype(load_tile_by_dsreadm(BDsreadm{}, warp_window)),
                                     KWarpIter>,
            NWarpIter>
            warp_tensors;

        using SFC =
            space_filling_curve<sequence<NWarpIter, KWarpIter>, sequence<0, 1>, sequence<1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto i) {
            constexpr auto idx = SFC::get_index(i);

            constexpr auto n_warp_iter = idx.at(number<0>{});
            constexpr auto k_warp_iter = idx.at(number<1>{});

            warp_tensors(n_warp_iter)(k_warp_iter) = load_tile_by_dsreadm(BDsreadm{}, warp_window);

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
        using SFC = space_filling_curve<sequence<MWarpIter, NWarpIter, KWarpIter>,
                                        sequence<0, 1, 2>,
                                        sequence<1, 1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SFC::get_index(access_id);

            constexpr auto m_warp_iter = idx.at(number<0>{});
            constexpr auto n_warp_iter = idx.at(number<1>{});
            constexpr auto k_warp_iter = idx.at(number<2>{});

            using CWarpDstr   = typename WG::CWarpDstr;
            using CWarpTensor = typename WG::CWarpTensor;

            constexpr auto c_warp_y_lengths =
                to_sequence(CWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto c_warp_y_index_zeros = uniform_sequence_gen_t<CWarpDstr::NDimY, 0>{};

            CWarpTensor c_warp_tensor;

            c_warp_tensor.get_thread_buffer() = c_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, c_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, c_warp_y_lengths));

            // warp GEMM
            WG{}(c_warp_tensor,
                 a_warp_tensors[m_warp_iter][k_warp_iter],
                 b_warp_tensors[n_warp_iter][k_warp_iter]);

            // write C warp tensor into C block tensor
            c_block_tensor.set_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, c_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, c_warp_y_lengths),
                c_warp_tensor.get_thread_buffer());
        });
    }

    CK_TILE_DEVICE static auto MakeCBlockTile()
    {
        // wave distribution encoding
        constexpr auto c_block_outer_dstr_encoding = tile_distribution_encoding<
            sequence<>,
            tuple<sequence<MWarpIter, MWarps>, sequence<NWarpIter, NWarps>>,
            tuple<sequence<1, 2>>,
            tuple<sequence<1, 1>>,
            sequence<1, 2>,
            sequence<0, 0>>{};

        // combine wave distribution and lane distribution
        constexpr auto c_block_dstr_encoding = detail::make_embed_tile_distribution_encoding(
            c_block_outer_dstr_encoding, typename WG::CWarpDstrEncoding{});

        constexpr auto c_block_dstr = make_static_tile_distribution(c_block_dstr_encoding);

        return make_static_distributed_tensor<typename Problem::AccDataType>(c_block_dstr);
    }
};

} // namespace ck_tile
