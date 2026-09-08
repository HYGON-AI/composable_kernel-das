// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv/utility/conv_fwd_spec_v2.hpp"
#include "ck_tile/ops/common.hpp"

namespace ck_tile {

template <index_t NDimSpatial,
          typename TileLengths,
          typename VectorLengths,
          ConvFwdSpecEnum Spec,
          bool PadDesc = true>
struct ConvFwdToGemmTransformerV2
{
    static constexpr index_t MPerTile = TileLengths::at(number<0>{});
    static constexpr index_t NPerTile = TileLengths::at(number<1>{});
    static constexpr index_t KPerTile = TileLengths::at(number<2>{});

    static constexpr index_t AVectorLength = VectorLengths::at(number<0>{});
    static constexpr index_t BVectorLength = VectorLengths::at(number<1>{});
    static constexpr index_t CVectorLength = VectorLengths::at(number<2>{});

    using Detail = detail::ConvFwdSpecDetail<Spec>;

    static constexpr auto FilterLengths = Detail::FilterLengths;
    static constexpr auto Strides       = Detail::Strides;
    static constexpr auto Dilations     = Detail::Dilations;
    static constexpr auto Pads          = Detail::Pads;

    static constexpr index_t NDim = NDimSpatial + 3;

    template <index_t tile_len>
    CK_TILE_HOST static auto ComputePadValue(const index_t raw_len, number<tile_len>)
    {
        return integer_divide_ceil(raw_len, tile_len) * tile_len - raw_len;
    }

    CK_TILE_HOST static auto MakeNPQPadTransform(const index_t N, const index_t P, const index_t Q)
    {
        const auto pad_val = ComputePadValue(N * P * Q, number<MPerTile>{});

        return conditional_expr<PadDesc>(make_right_pad_transform(N * P * Q, pad_val),
                                         make_pass_through_transform(N * P * Q));
    }

    CK_TILE_HOST static auto MakeKPadTransform(const index_t K)
    {
        const auto pad_val = ComputePadValue(K, number<NPerTile>{});

        return conditional_expr<PadDesc>(make_right_pad_transform(K, pad_val),
                                         make_pass_through_transform(K));
    }

    CK_TILE_HOST static auto MakeCPadTransform(const index_t C)
    {
        const auto pad_val = ComputePadValue(C, number<KPerTile>{});

        return conditional_expr<PadDesc>(make_right_pad_transform(C, pad_val),
                                         make_pass_through_transform(C));
    }

    // Input -> GemmA
    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<ALayout, tensor_layout::convolution::NHWGC>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeADescriptor_M_K(const std::array<index_t, NDim>& a_g_n_c_wis_lengths,
                        const std::array<index_t, NDim>& a_g_n_c_wis_strides,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_lengths */,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */,
                        const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& /* c_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        constexpr auto Y = FilterLengths[0];
        constexpr auto X = FilterLengths[1];

        constexpr auto ConvStrideH = Strides[0];
        constexpr auto ConvStrideW = Strides[1];

        constexpr auto ConvDilationH = Dilations[0];
        constexpr auto ConvDilationW = Dilations[1];

        constexpr auto InLeftPadH = Pads[0];
        constexpr auto InLeftPadW = Pads[1];

        constexpr auto InRightPadH = Pads[2];
        constexpr auto InRightPadW = Pads[3];

        const index_t N = a_g_n_c_wis_lengths[1];
        const index_t C = a_g_n_c_wis_lengths[2];
        const index_t H = a_g_n_c_wis_lengths[3];
        const index_t W = a_g_n_c_wis_lengths[4];
        const index_t P = c_g_n_k_wos_lengths[3];
        const index_t Q = c_g_n_k_wos_lengths[4];

        // make N, C padded transforms
        const auto trans_pad_npq = MakeNPQPadTransform(N, P, Q);
        const auto trans_pad_c   = MakeCPadTransform(C);
        const auto CPadded       = trans_pad_c.get_upper_lengths()[number<0>{}];

        const auto in_n_h_w_c_desc = make_naive_tensor_descriptor(make_tuple(N, H, W, C),
                                                                  make_tuple(a_g_n_c_wis_strides[1],
                                                                             a_g_n_c_wis_strides[3],
                                                                             a_g_n_c_wis_strides[4],
                                                                             number<1>{}),
                                                                  number<AVectorLength>{},
                                                                  number<1>{});

        const auto in_n_hp_wp_cp_desc = transform_tensor_descriptor(
            in_n_h_w_c_desc,
            make_tuple(make_pass_through_transform(N),
                       make_pad_transform(H, InLeftPadH, InRightPadH),
                       make_pad_transform(W, InLeftPadW, InRightPadW),
                       trans_pad_c),
            make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
            make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}));

        const auto in_n_y_p_x_q_cp_desc = transform_tensor_descriptor(
            in_n_hp_wp_cp_desc,
            make_tuple(
                make_pass_through_transform(N),
                make_embed_transform(make_tuple(Y, P), make_tuple(ConvDilationH, ConvStrideH)),
                make_embed_transform(make_tuple(X, Q), make_tuple(ConvDilationW, ConvStrideW)),
                make_pass_through_transform(CPadded)),
            make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
            make_tuple(sequence<0>{}, sequence<1, 2>{}, sequence<3, 4>{}, sequence<5>{}));

        const auto in_npq_yxcp_desc =
            transform_tensor_descriptor(in_n_y_p_x_q_cp_desc,
                                        make_tuple(make_merge_transform(make_tuple(N, P, Q)),
                                                   make_merge_transform(make_tuple(Y, X, CPadded))),
                                        make_tuple(sequence<0, 2, 4>{}, sequence<1, 3, 5>{}),
                                        make_tuple(sequence<0>{}, sequence<1>{}));

        const auto in_gemmm_gemmk_desc = transform_tensor_descriptor(
            in_npq_yxcp_desc,
            make_tuple(trans_pad_npq, make_pass_through_transform(Y * X * CPadded)),
            make_tuple(sequence<0>{}, sequence<1>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));

        return in_gemmm_gemmk_desc;
    }

    // Weight -> GemmB
    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<BLayout, tensor_layout::convolution::GKYXC>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */)
    {
        constexpr auto Y = FilterLengths[0];
        constexpr auto X = FilterLengths[1];

        const index_t K = b_g_k_c_xs_lengths[1];
        const index_t C = b_g_k_c_xs_lengths[2];

        // make K, C padded transforms
        const auto trans_pad_k = MakeKPadTransform(K);
        const auto trans_pad_c = MakeCPadTransform(C);
        const auto KPadded     = trans_pad_k.get_upper_lengths()[number<0>{}];
        const auto CPadded     = trans_pad_c.get_upper_lengths()[number<0>{}];

        const auto wei_k_y_x_c_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, Y, X, C), number<BVectorLength>{});

        const auto wei_kp_y_x_cp_desc = transform_tensor_descriptor(
            wei_k_y_x_c_desc,
            make_tuple(trans_pad_k,
                       make_pass_through_transform(Y),
                       make_pass_through_transform(X),
                       trans_pad_c),
            make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
            make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}));

        const auto wei_gemmn_gemmk_desc =
            transform_tensor_descriptor(wei_kp_y_x_cp_desc,
                                        make_tuple(make_pass_through_transform(KPadded),
                                                   make_merge_transform(make_tuple(Y, X, CPadded))),
                                        make_tuple(sequence<0>{}, sequence<1, 2, 3>{}),
                                        make_tuple(sequence<0>{}, sequence<1>{}));

        return wei_gemmn_gemmk_desc;
    }

    // Ouptut -> GemmC
    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<CLayout, tensor_layout::convolution::NHWGK>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& c_g_n_k_wos_strides)
    {
        const index_t N = c_g_n_k_wos_lengths[1];
        const index_t P = c_g_n_k_wos_lengths[3];
        const index_t Q = c_g_n_k_wos_lengths[4];
        const index_t K = c_g_n_k_wos_lengths[2];

        // make N, K pad transforms
        const auto trans_pad_npq = MakeNPQPadTransform(N, P, Q);
        const auto trans_pad_k   = MakeKPadTransform(K);
        const auto KPadded       = trans_pad_k.get_upper_lengths()[number<0>{}];

        const auto out_n_p_q_k_desc =
            make_naive_tensor_descriptor(make_tuple(N, P, Q, K),
                                         make_tuple(c_g_n_k_wos_strides[1],
                                                    c_g_n_k_wos_strides[3],
                                                    c_g_n_k_wos_strides[4],
                                                    c_g_n_k_wos_strides[2]),
                                         number<CVectorLength>{},
                                         number<1>{});

        const auto out_npq_kp_desc = transform_tensor_descriptor(
            out_n_p_q_k_desc,
            make_tuple(make_merge_transform(make_tuple(N, P, Q)), trans_pad_k),
            make_tuple(sequence<0, 1, 2>{}, sequence<3>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));

        const auto out_gemmm_gemmn_desc = transform_tensor_descriptor(
            out_npq_kp_desc,
            make_tuple(trans_pad_npq, make_pass_through_transform(KPadded)),
            make_tuple(sequence<0>{}, sequence<1>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));

        return out_gemmm_gemmn_desc;
    }

    // Input -> GemmA
    template <typename ALayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          std::is_same_v<ALayout, tensor_layout::gemm::RowMajor>,
                                      bool>::type = false>
    CK_TILE_HOST static auto
    MakeADescriptor_M_K(const std::array<index_t, NDim>& a_g_n_c_wis_lengths,
                        const std::array<index_t, NDim>& a_g_n_c_wis_strides,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_lengths */,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */,
                        const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& /* c_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        static_assert(Spec == ConvFwdSpecEnum::F1x1_S1_D1_P0);

        const index_t N = a_g_n_c_wis_lengths[1];
        const index_t C = a_g_n_c_wis_lengths[2];
        const index_t P = c_g_n_k_wos_lengths[3];
        const index_t Q = c_g_n_k_wos_lengths[4];

        const auto pad_val_gemmm   = ComputePadValue(N * P * Q, number<MPerTile>{});
        const auto trans_gemmm_pad = make_right_pad_transform(N * P * Q, pad_val_gemmm);

        const auto pad_val_gemmk   = ComputePadValue(C, number<KPerTile>{});
        const auto trans_gemmk_pad = make_right_pad_transform(C, pad_val_gemmk);

        const auto in_gemmmraw_gemmkraw_desc =
            make_naive_tensor_descriptor(make_tuple(N * P * Q, C),
                                         make_tuple(a_g_n_c_wis_strides[4], number<1>{}),
                                         number<AVectorLength>{},
                                         number<1>{});

        return transform_tensor_descriptor(in_gemmmraw_gemmkraw_desc,
                                           make_tuple(trans_gemmm_pad, trans_gemmk_pad),
                                           make_tuple(sequence<0>{}, sequence<1>{}),
                                           make_tuple(sequence<0>{}, sequence<1>{}));
    }

    // Weight -> GemmB
    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          std::is_same_v<BLayout, tensor_layout::gemm::RowMajor>,
                                      bool>::type = false>
    CK_TILE_HOST static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */)
    {
        static_assert(Spec == ConvFwdSpecEnum::F1x1_S1_D1_P0);

        const index_t K = b_g_k_c_xs_lengths[1];
        const index_t C = b_g_k_c_xs_lengths[2];

        const auto pad_val_gemmn   = ComputePadValue(K, number<NPerTile>{});
        const auto trans_gemmn_pad = make_right_pad_transform(K, pad_val_gemmn);

        const auto pad_val_gemmk   = ComputePadValue(C, number<KPerTile>{});
        const auto trans_gemmk_pad = make_right_pad_transform(C, pad_val_gemmk);

        const auto wei_gemmnraw_gemmkraw_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, C), number<BVectorLength>{});

        return transform_tensor_descriptor(wei_gemmnraw_gemmkraw_desc,
                                           make_tuple(trans_gemmn_pad, trans_gemmk_pad),
                                           make_tuple(sequence<0>{}, sequence<1>{}),
                                           make_tuple(sequence<0>{}, sequence<1>{}));
    }

    // Ouptut -> GemmC
    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          std::is_same_v<CLayout, tensor_layout::gemm::RowMajor>,
                                      bool>::type = false>
    CK_TILE_HOST static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& c_g_n_k_wos_strides)
    {

        static_assert(Spec == ConvFwdSpecEnum::F1x1_S1_D1_P0);

        const index_t N = c_g_n_k_wos_lengths[1];
        const index_t P = c_g_n_k_wos_lengths[3];
        const index_t Q = c_g_n_k_wos_lengths[4];
        const index_t K = c_g_n_k_wos_lengths[2];

        const auto pad_val_gemmm   = ComputePadValue(N * P * Q, number<MPerTile>{});
        const auto trans_gemmm_pad = make_right_pad_transform(N * P * Q, pad_val_gemmm);

        const auto pad_val_gemmn   = ComputePadValue(K, number<NPerTile>{});
        const auto trans_gemmn_pad = make_right_pad_transform(K, pad_val_gemmn);

        const auto out_gemmmraw_gemmnraw_desc =
            make_naive_tensor_descriptor(make_tuple(N * P * Q, K),
                                         make_tuple(c_g_n_k_wos_strides[4], number<1>{}),
                                         number<CVectorLength>{},
                                         number<1>{});

        return transform_tensor_descriptor(out_gemmmraw_gemmnraw_desc,
                                           make_tuple(trans_gemmm_pad, trans_gemmn_pad),
                                           make_tuple(sequence<0>{}, sequence<1>{}),
                                           make_tuple(sequence<0>{}, sequence<1>{}));
    }
};

} // namespace ck_tile
