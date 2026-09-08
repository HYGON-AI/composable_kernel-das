// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv/warp/warp_gemm_dispatcher.hpp"
#include "ck_tile/ops/gemm/warp/warp_dsreadm_format_dispatcher.hpp"

namespace ck_tile {

template <typename Problem>
struct BlockGemmMmacTNAsmemBsmemCregTlsWaspV1
{
    using ADataType   = remove_cvref_t<typename Problem::InDataType>;
    using BDataType   = remove_cvref_t<typename Problem::WeiDataType>;
    using AccDataType = remove_cvref_t<typename Problem::AccDataType>;

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

    // tls tile
    static constexpr index_t MPerTlsLoad = MmmacIter * MPerMmac * MmmacInterleave;
    static constexpr index_t NPerTlsLoad = NmmacIter * NPerMmac * NmmacInterleave;
    static constexpr index_t KPerTlsLoad = KPerBlock;

    using AWarpDsreadmFormat =
        WarpDsreadmFormatDispatcher<ADataType, MmmacIter, MPerMmac, MmmacInterleave, true>;
    using BWarpDsreadmFormat =
        WarpDsreadmFormatDispatcher<BDataType, NmmacIter, NPerMmac, NmmacInterleave, true>;

    // ds read immed offsets
    static constexpr index_t ALdsWarpElemOffsetM = MPerTlsLoad * KPerTlsLoad;
    static constexpr index_t BLdsWarpElemOffsetN = NPerTlsLoad * KPerTlsLoad;
    static constexpr index_t ALdsImmedOffsetM =
        ALdsWarpElemOffsetM * MWarpsPerWG * sizeof(ADataType);
    static constexpr index_t BLdsImmedOffsetN =
        BLdsWarpElemOffsetN * NWarpsPerWG * sizeof(BDataType);
    static constexpr index_t ALdsImmedOffsetK = AWarpDsreadmFormat::Impl::kK * sizeof(ADataType);
    static constexpr index_t BLdsImmedOffsetK = BWarpDsreadmFormat::Impl::kK * sizeof(BDataType);

    static constexpr auto KIter =
        (AWarpDsreadmFormat::kKStoreLane * AWarpDsreadmFormat::kKStorePerLane) /
        conv::WarpGemmMmacDispatcher<ADataType,
                                     BDataType,
                                     AccDataType,
                                     MmmacIter,
                                     NmmacIter,
                                     MPerMmac,
                                     NPerMmac,
                                     MmmacInterleave,
                                     NmmacInterleave,
                                     1,
                                     true>::kK;

    using WarpGemm = conv::WarpGemmMmacDispatcher<ADataType,
                                                  BDataType,
                                                  AccDataType,
                                                  MmmacIter,
                                                  NmmacIter,
                                                  MPerMmac,
                                                  NPerMmac,
                                                  MmmacInterleave,
                                                  NmmacInterleave,
                                                  KIter,
                                                  true>;

    // tile per outer iter
    static constexpr index_t MPerBlockPerIter = MWarpsPerWG * WarpGemm::kM;
    static constexpr index_t NPerBlockPerIter = NWarpsPerWG * WarpGemm::kN;

    static constexpr index_t KWarpIter = KPerBlock / WarpGemm::kK;

    CK_TILE_DEVICE BlockGemmMmacTNAsmemBsmemCregTlsWaspV1()
    {
        static_assert(Problem::WGSize == MWarpsPerWG * NWarpsPerWG * get_warp_size(),
                      "WGSize != MWarpsPerWG * NWarpsPerWG * get_warp_size()");

        static_assert(MPerWG % (MWarpIterPerWG * MmmacIter * MPerMmac * MmmacInterleave) == 0,
                      "wrong!");

        static_assert(NPerWG % (NWarpIterPerWG * NmmacIter * NPerMmac * NmmacInterleave) == 0,
                      "wrong!");

        const index_t warp_id_m = ck_tile::get_sub_warp_id(Problem::SubWGSize) / NWarpsPerWG;
        const index_t warp_id_n = ck_tile::get_sub_warp_id(Problem::SubWGSize) % NWarpsPerWG;

        a_warp_lds_elem_offset = warp_id_m * ALdsWarpElemOffsetM;
        b_warp_lds_elem_offset = warp_id_n * BLdsWarpElemOffsetN;
    }

    template <typename LdsWindow>
    CK_TILE_DEVICE auto GetAWarpTensors(LdsWindow& lds_window) const
    {
        using vector_t = ext_vector_t<ADataType, AWarpDsreadmFormat::kVectorLength>;

        CK_TILE_LDS_ADDR ADataType* smem_ptr = lds_window.get_buffer_ptr();

        return generate_tuple(
            [&](auto i) {
                constexpr auto k_warp_iter = i % KWarpIter;
                constexpr auto m_warp_iter = i / KWarpIter;

                constexpr auto immed_offset =
                    number<m_warp_iter * ALdsImmedOffsetM + k_warp_iter * ALdsImmedOffsetK>{};

                vector_t vec_value = bit_cast<vector_t>(
                    AWarpDsreadmFormat{}(smem_ptr + a_warp_lds_elem_offset, immed_offset));

                auto warp_tensor =
                    make_static_distributed_tensor<ADataType>(make_static_tile_distribution(
                        typename AWarpDsreadmFormat::WarpStoreDstrEncoding{}));

                warp_tensor.get_thread_buffer().template get_as<vector_t>()(number<0>{}) =
                    vec_value;
                return warp_tensor;
            },
            number<MWarpIterPerWG * KWarpIter>{});
    }

    template <typename LdsWindow>
    CK_TILE_DEVICE auto GetBWarpTensors(LdsWindow& lds_window) const
    {
        using vector_t = ext_vector_t<BDataType, BWarpDsreadmFormat::kVectorLength>;

        CK_TILE_LDS_ADDR BDataType* smem_ptr = lds_window.get_buffer_ptr();

        return generate_tuple(
            [&](auto i) {
                constexpr auto k_warp_iter = i % KWarpIter;
                constexpr auto n_warp_iter = i / KWarpIter;

                constexpr auto immed_offset =
                    number<n_warp_iter * BLdsImmedOffsetN + k_warp_iter * BLdsImmedOffsetK>{};

                vector_t vec_value = bit_cast<vector_t>(
                    BWarpDsreadmFormat{}(smem_ptr + b_warp_lds_elem_offset, immed_offset));

                auto warp_tensor =
                    make_static_distributed_tensor<BDataType>(make_static_tile_distribution(
                        typename BWarpDsreadmFormat::WarpStoreDstrEncoding{}));

                warp_tensor.get_thread_buffer().template get_as<vector_t>()(number<0>{}) =
                    vec_value;
                return warp_tensor;
            },
            number<NWarpIterPerWG * KWarpIter>{});
    }

    template <typename AccBlockTensor, typename AWarpTensors, typename BWarpTensors>
    CK_TILE_DEVICE void operator()(AccBlockTensor& acc_block_tensor,
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

            using AccWarpDstr   = typename WarpGemm::CWarpDstr;
            using AccWarpTensor = typename WarpGemm::CWarpTensor;

            constexpr auto acc_warp_y_lengths =
                to_sequence(AccWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto acc_warp_y_index_zeros = uniform_sequence_gen_t<AccWarpDstr::NDimY, 0>{};

            AccWarpTensor acc_warp_tensor;

            acc_warp_tensor.get_thread_buffer() = acc_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, acc_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_y_lengths));

            // warp GEMM
            WarpGemm{}(acc_warp_tensor,
                       a_warp_tensors[number<m_warp_iter * KWarpIter + k_warp_iter>{}],
                       b_warp_tensors[number<n_warp_iter * KWarpIter + k_warp_iter>{}]);

            // write acc_warp_tensor into acc_block_tensor
            acc_block_tensor.set_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, acc_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_y_lengths),
                acc_warp_tensor.get_thread_buffer());
        });
    }

    CK_TILE_DEVICE static auto MakeAccBlockTile()
    {
        // wave distribution encoding
        constexpr auto acc_block_outer_dstr_encoding = tile_distribution_encoding<
            sequence<>,
            tuple<sequence<MWarpIterPerWG, MWarpsPerWG>, sequence<NWarpIterPerWG, NWarpsPerWG>>,
            tuple<sequence<1, 2>>,
            tuple<sequence<1, 1>>,
            sequence<1, 2>,
            sequence<0, 0>>{};

        // combine wave distribution and lane distribution
        constexpr auto acc_block_dstr_encoding = detail::make_embed_tile_distribution_encoding(
            acc_block_outer_dstr_encoding, typename WarpGemm::CWarpDstrEncoding{});

        constexpr auto acc_block_dstr = make_static_tile_distribution(
            acc_block_dstr_encoding, bool_constant<true>{}, Problem::SubWGSize);

        return make_static_distributed_tensor<typename Problem::AccDataType>(acc_block_dstr);
    }

    template <typename AccBlockTensor>
    CK_TILE_DEVICE static auto MakePermutedAccBlockTile(const AccBlockTensor& acc_block_tensor)
    {
        // wave distribution encoding
        constexpr auto acc_block_outer_dstr_encoding = tile_distribution_encoding<
            sequence<>,
            tuple<sequence<MWarpIterPerWG, MWarpsPerWG>, sequence<NWarpIterPerWG, NWarpsPerWG>>,
            tuple<sequence<1, 2>>,
            tuple<sequence<1, 1>>,
            sequence<1, 2>,
            sequence<0, 0>>{};

        // combine wave distribution and lane distribution
        constexpr auto acc_block_permute_dstr_encoding =
            detail::make_embed_tile_distribution_encoding(
                acc_block_outer_dstr_encoding,
                typename WarpGemm::WarpGemmAttribute::CWarpPermuteDstrEncoding{});

        constexpr auto acc_block_permute_dstr = make_static_tile_distribution(
            acc_block_permute_dstr_encoding, bool_constant<true>{}, Problem::SubWGSize);

        auto acc_block_permute_tensor =
            make_static_distributed_tensor<typename Problem::AccDataType>(acc_block_permute_dstr);

        using SFC = space_filling_curve<sequence<MWarpIterPerWG, NWarpIterPerWG>,
                                        sequence<0, 1>,
                                        sequence<1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SFC::get_index(access_id);

            constexpr auto m_warp_iter = idx.at(number<0>{});
            constexpr auto n_warp_iter = idx.at(number<1>{});

            using AccWarpDstr   = typename WarpGemm::CWarpDstr;
            using AccWarpTensor = typename WarpGemm::CWarpTensor;

            constexpr auto acc_warp_y_lengths =
                to_sequence(AccWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto acc_warp_y_index_zeros = uniform_sequence_gen_t<AccWarpDstr::NDimY, 0>{};

            AccWarpTensor acc_warp_tensor;

            acc_warp_tensor.get_thread_buffer() = acc_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, acc_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_y_lengths));

            auto acc_warp_permute_tensor =
                WarpGemm::WarpGemmAttribute::GetCWarpPermuteTensor(acc_warp_tensor);

            using AccWarpPermuteDstr = remove_cvref_t<decltype(make_static_tile_distribution(
                typename WarpGemm::WarpGemmAttribute::CWarpPermuteDstrEncoding{},
                bool_constant<true>{},
                Problem::SubWGSize))>;

            constexpr auto acc_warp_permute_y_lengths =
                to_sequence(AccWarpPermuteDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto acc_warp_permute_y_index_zeros =
                uniform_sequence_gen_t<AccWarpPermuteDstr::NDimY, 0>{};

            acc_block_permute_tensor.set_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{},
                                acc_warp_permute_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_permute_y_lengths),
                acc_warp_permute_tensor.get_thread_buffer());
        });

        return acc_block_permute_tensor;
    }

    index_t a_warp_lds_elem_offset, b_warp_lds_elem_offset;
};

} // namespace ck_tile
