// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv/warp/warp_gemm_dispatcher.hpp"
#include "ck_tile/ops/gemm/warp/warp_dsreadm_format_dispatcher.hpp"

namespace ck_tile {

template <typename Problem>
struct BlockGemmMmacTNAsmemBsmemCregTlsV1
{
    using ADataType   = remove_cvref_t<typename Problem::InDataType>;
    using BDataType   = remove_cvref_t<typename Problem::WeiDataType>;
    using AccDataType = remove_cvref_t<typename Problem::AccDataType>;

    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t BlockSize = Problem::BlockSize;

    static constexpr index_t MWarps = Problem::MWarps;
    static constexpr index_t NWarps = Problem::NWarps;

    static constexpr index_t MWarpIter = Problem::MWarpIter;
    static constexpr index_t NWarpIter = Problem::NWarpIter;

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
    static constexpr index_t ALdsImmedOffsetM    = ALdsWarpElemOffsetM * MWarps * sizeof(ADataType);
    static constexpr index_t BLdsImmedOffsetN    = BLdsWarpElemOffsetN * NWarps * sizeof(BDataType);
    static constexpr index_t ALdsImmedOffsetK    = AWarpDsreadmFormat::Impl::kK * sizeof(ADataType);
    static constexpr index_t BLdsImmedOffsetK    = BWarpDsreadmFormat::Impl::kK * sizeof(BDataType);

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
    static constexpr index_t MPerBlockPerIter = MWarps * WarpGemm::kM;
    static constexpr index_t NPerBlockPerIter = NWarps * WarpGemm::kN;

    static constexpr index_t KWarpIter = KPerBlock / WarpGemm::kK;

    CK_TILE_DEVICE BlockGemmMmacTNAsmemBsmemCregTlsV1()
    {
        static_assert(BlockSize == MWarps * NWarps * get_warp_size(),
                      "BlockSize != MWarps * NWarps * get_warp_size()");

        static_assert(MPerBlock % (MWarpIter * MmmacIter * MPerMmac * MmmacInterleave) == 0,
                      "wrong!");

        static_assert(NPerBlock % (NWarpIter * NmmacIter * NPerMmac * NmmacInterleave) == 0,
                      "wrong!");

        const index_t warp_id_m = ck_tile::get_warp_id() / NWarps;
        const index_t warp_id_n = ck_tile::get_warp_id() % NWarps;

        a_warp_lds_elem_offset = warp_id_m * ALdsWarpElemOffsetM;
        b_warp_lds_elem_offset = warp_id_n * BLdsWarpElemOffsetN;
    }

    template <bool use_m0 = true>
    CK_TILE_DEVICE auto GetAWarpTensors(CK_TILE_LDS_ADDR ADataType* smem_ptr,
                                        bool_constant<use_m0> = {}) const
    {
        using vector_t = ext_vector_t<ADataType, AWarpDsreadmFormat::kVectorLength>;

        return generate_tuple(
            [&](auto i) {
                constexpr auto k_warp_iter = i % KWarpIter;
                constexpr auto m_warp_iter = i / KWarpIter;

                constexpr auto immed_offset =
                    number<m_warp_iter * ALdsImmedOffsetM + k_warp_iter * ALdsImmedOffsetK>{};

                vector_t vec_value = bit_cast<vector_t>(AWarpDsreadmFormat{}(
                    smem_ptr + a_warp_lds_elem_offset, immed_offset, bool_constant<use_m0>{}));

                auto warp_tensor =
                    make_static_distributed_tensor<ADataType>(make_static_tile_distribution(
                        typename AWarpDsreadmFormat::WarpStoreDstrEncoding{}));

                warp_tensor.get_thread_buffer().template get_as<vector_t>()(number<0>{}) =
                    vec_value;
                return warp_tensor;
            },
            number<MWarpIter * KWarpIter>{});
    }

    template <bool use_m0 = true>
    CK_TILE_DEVICE auto GetBWarpTensors(CK_TILE_LDS_ADDR BDataType* smem_ptr,
                                        bool_constant<use_m0> = {}) const
    {
        using vector_t = ext_vector_t<BDataType, BWarpDsreadmFormat::kVectorLength>;

        return generate_tuple(
            [&](auto i) {
                constexpr auto k_warp_iter = i % KWarpIter;
                constexpr auto n_warp_iter = i / KWarpIter;

                constexpr auto immed_offset =
                    number<n_warp_iter * BLdsImmedOffsetN + k_warp_iter * BLdsImmedOffsetK>{};

                vector_t vec_value = bit_cast<vector_t>(BWarpDsreadmFormat{}(
                    smem_ptr + b_warp_lds_elem_offset, immed_offset, bool_constant<use_m0>{}));

                auto warp_tensor =
                    make_static_distributed_tensor<BDataType>(make_static_tile_distribution(
                        typename BWarpDsreadmFormat::WarpStoreDstrEncoding{}));

                warp_tensor.get_thread_buffer().template get_as<vector_t>()(number<0>{}) =
                    vec_value;
                return warp_tensor;
            },
            number<NWarpIter * KWarpIter>{});
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
                       a_warp_tensors[number<m_warp_iter * KWarpIter + k_warp_iter>{}],
                       b_warp_tensors[number<n_warp_iter * KWarpIter + k_warp_iter>{}]);

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
            c_block_outer_dstr_encoding, typename WarpGemm::CWarpDstrEncoding{});

        constexpr auto c_block_dstr = make_static_tile_distribution(c_block_dstr_encoding);

        return make_static_distributed_tensor<typename Problem::AccDataType>(c_block_dstr);
    }

    template <typename CBlockTensor>
    CK_TILE_DEVICE static auto MakeCBlockPermuteTile(const CBlockTensor& c_block_tensor)
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
        constexpr auto c_block_permute_dstr_encoding =
            detail::make_embed_tile_distribution_encoding(
                c_block_outer_dstr_encoding,
                typename WarpGemm::WarpGemmAttribute::CWarpPermuteDstrEncoding{});

        constexpr auto c_block_permute_dstr =
            make_static_tile_distribution(c_block_permute_dstr_encoding);

        auto c_block_permute_tensor =
            make_static_distributed_tensor<typename Problem::AccDataType>(c_block_permute_dstr);

        using SFC =
            space_filling_curve<sequence<MWarpIter, NWarpIter>, sequence<0, 1>, sequence<1, 1>>;

        constexpr auto num_access = SFC::get_num_of_access();

        static_for<0, num_access, 1>{}([&](auto access_id) {
            constexpr auto idx = SFC::get_index(access_id);

            constexpr auto m_warp_iter = idx.at(number<0>{});
            constexpr auto n_warp_iter = idx.at(number<1>{});

            using CWarpDstr   = typename WarpGemm::CWarpDstr;
            using CWarpTensor = typename WarpGemm::CWarpTensor;

            constexpr auto c_warp_y_lengths =
                to_sequence(CWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto c_warp_y_index_zeros = uniform_sequence_gen_t<CWarpDstr::NDimY, 0>{};

            CWarpTensor c_warp_tensor;

            c_warp_tensor.get_thread_buffer() = c_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, c_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, c_warp_y_lengths));

            auto c_warp_permute_tensor =
                WarpGemm::WarpGemmAttribute::GetCWarpPermuteTensor(c_warp_tensor);

            using CWarpPermuteDstr = remove_cvref_t<decltype(make_static_tile_distribution(
                typename WarpGemm::WarpGemmAttribute::CWarpPermuteDstrEncoding{}))>;

            constexpr auto c_warp_permute_y_lengths =
                to_sequence(CWarpPermuteDstr{}.get_ys_to_d_descriptor().get_lengths());
            constexpr auto c_warp_permute_y_index_zeros =
                uniform_sequence_gen_t<CWarpPermuteDstr::NDimY, 0>{};

            c_block_permute_tensor.set_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, c_warp_permute_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, c_warp_permute_y_lengths),
                c_warp_permute_tensor.get_thread_buffer());
        });

        return c_block_permute_tensor;
    }

    index_t a_warp_lds_elem_offset, b_warp_lds_elem_offset;
};

} // namespace ck_tile
