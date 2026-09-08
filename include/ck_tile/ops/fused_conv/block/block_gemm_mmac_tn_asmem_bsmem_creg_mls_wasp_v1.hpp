// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv/warp/warp_gemm_dispatcher.hpp"
#include "ck_tile/ops/fused_conv/block/block_gemm_mmac_tn_asmem_bsmem_creg_tls_v1.hpp"

namespace ck_tile {

template <hcu_target_enum HcuArch, typename Problem>
struct BlockGemmMmacTNAsmemBsmemCregMlsWaspV1
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

    using ATileTraits = tile_window_mls_traits<sequence<MPerWG, KPerBlock>,
                                               sizeof(ADataType),
                                               MmmacInterleave,
                                               true,
                                               HcuArch>;

    using BTileTraits = tile_window_mls_traits<sequence<NPerWG, KPerBlock>,
                                               sizeof(BDataType),
                                               NmmacInterleave,
                                               true,
                                               HcuArch>;

    static constexpr auto ALdsDesc = ATileTraits::Detail::make_lds_desc();
    static constexpr auto BLdsDesc = BTileTraits::Detail::make_lds_desc();

    using ADsFormatInst = typename mls_ds_traits<typename ATileTraits::Detail::MlsAtom,
                                                 sizeof(ADataType),
                                                 MmmacInterleave>::Type;

    using BDsFormatInst = typename mls_ds_traits<typename BTileTraits::Detail::MlsAtom,
                                                 sizeof(BDataType),
                                                 NmmacInterleave>::Type;

    static constexpr auto MPerWarpRead = ADsFormatInst::kMN;
    static constexpr auto NPerWarpRead = BDsFormatInst::kMN;
    static constexpr auto KPerWarpRead = ADsFormatInst::kK;

    static_assert(ADsFormatInst::kK == BDsFormatInst::kK);

    static constexpr auto MPerWGRead = MPerWarpRead * MWarpsPerWG;
    static constexpr auto NPerWGRead = NPerWarpRead * NWarpsPerWG;

    static constexpr auto KIter = KPerWarpRead / conv::WarpGemmMmacDispatcher<ADataType,
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

    static constexpr index_t KWarpIter = KPerBlock / WarpGemm::kK;

    CK_TILE_DEVICE BlockGemmMmacTNAsmemBsmemCregMlsWaspV1()
    {
        static_assert(Problem::WGSize == MWarpsPerWG * NWarpsPerWG * get_warp_size(),
                      "WGSize != MWarpsPerWG * NWarpsPerWG * get_warp_size()");

        static_assert(MPerWG % (MWarpIterPerWG * MmmacIter * MPerMmac * MmmacInterleave) == 0,
                      "wrong!");

        static_assert(NPerWG % (NWarpIterPerWG * NmmacIter * NPerMmac * NmmacInterleave) == 0,
                      "wrong!");

        const index_t warp_coord_m =
            (ck_tile::get_sub_warp_id(Problem::SubWGSize) / NWarpsPerWG) * MPerWarpRead;
        const index_t warp_coord_n =
            (ck_tile::get_sub_warp_id(Problem::SubWGSize) % NWarpsPerWG) * NPerWarpRead;

        a_warp_lds_elem_offset = ALdsDesc.calculate_offset(make_multi_index(warp_coord_m, 0));
        b_warp_lds_elem_offset = BLdsDesc.calculate_offset(make_multi_index(warp_coord_n, 0));
    }

    template <typename LdsWindow>
    CK_TILE_DEVICE auto GetAWarpTensors(LdsWindow& lds_window) const
    {
        using vector_t = ext_vector_t<ADataType, ADsFormatInst::kVectorLength>;

        CK_TILE_LDS_ADDR ADataType* smem_ptr = lds_window.get_buffer_ptr();

        using SFC = space_filling_curve<sequence<MWarpIterPerWG, KWarpIter>,
                                        sequence<0, 1>,
                                        sequence<1, 1>,
                                        false>;

        constexpr auto num_access = SFC::get_num_of_access();

        return generate_tuple(
            [&](auto i) {
                constexpr auto idx = SFC::get_index(i);

                constexpr auto m_warp_iter = idx.at(number<0>{});
                constexpr auto k_warp_iter = idx.at(number<1>{});

                constexpr auto immed_offset =
                    ALdsDesc.calculate_offset(
                        make_multi_index(m_warp_iter * MPerWGRead, k_warp_iter * KPerWarpRead)) *
                    sizeof(ADataType);

                constexpr bool skip_mov_m0 = (i != 0);

                vector_t vec_value =
                    bit_cast<vector_t>(ADsFormatInst{}(smem_ptr + a_warp_lds_elem_offset,
                                                       number<immed_offset>{},
                                                       bool_constant<false>{},
                                                       bool_constant<skip_mov_m0>{}));

                auto warp_tensor = make_static_distributed_tensor<ADataType>(
                    make_static_tile_distribution(typename ADsFormatInst::WarpStoreDstrEncoding{}));

                warp_tensor.get_thread_buffer().template get_as<vector_t>()(number<0>{}) =
                    vec_value;

                return warp_tensor;
            },
            number<num_access>{});
    }

    template <typename LdsWindow>
    CK_TILE_DEVICE auto GetBWarpTensors(LdsWindow& lds_window) const
    {
        using vector_t = ext_vector_t<BDataType, BDsFormatInst::kVectorLength>;

        CK_TILE_LDS_ADDR BDataType* smem_ptr = lds_window.get_buffer_ptr();

        using SFC = space_filling_curve<sequence<NWarpIterPerWG, KWarpIter>,
                                        sequence<0, 1>,
                                        sequence<1, 1>,
                                        false>;

        constexpr auto num_access = SFC::get_num_of_access();

        return generate_tuple(
            [&](auto i) {
                constexpr auto idx = SFC::get_index(i);

                constexpr auto n_warp_iter = idx.at(number<0>{});
                constexpr auto k_warp_iter = idx.at(number<1>{});

                constexpr auto immed_offset =
                    ALdsDesc.calculate_offset(
                        make_multi_index(n_warp_iter * NPerWGRead, k_warp_iter * KPerWarpRead)) *
                    sizeof(BDataType);

                constexpr bool skip_mov_m0 = (i != 0);

                vector_t vec_value =
                    bit_cast<vector_t>(BDsFormatInst{}(smem_ptr + b_warp_lds_elem_offset,
                                                       number<immed_offset>{},
                                                       bool_constant<false>{},
                                                       bool_constant<skip_mov_m0>{}));

                auto warp_tensor = make_static_distributed_tensor<ADataType>(
                    make_static_tile_distribution(typename BDsFormatInst::WarpStoreDstrEncoding{}));

                warp_tensor.get_thread_buffer().template get_as<vector_t>()(number<0>{}) =
                    vec_value;

                return warp_tensor;
            },
            number<num_access>{});
    }

    template <typename AccBlockTensor, typename AWarpTensors, typename BWarpTensors>
    CK_TILE_DEVICE void operator()(AccBlockTensor& acc_block_tensor,
                                   const AWarpTensors& a_warp_tensors,
                                   const BWarpTensors& b_warp_tensors) const
    {
        using SFC = space_filling_curve<sequence<MWarpIterPerWG, NWarpIterPerWG, KWarpIter>,
                                        sequence<0, 1, 2>,
                                        sequence<1, 1, 1>,
                                        false>;

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
