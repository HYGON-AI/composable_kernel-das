// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv/utility/conv_fwd_spec.hpp"
#include "ck_tile/ops/common.hpp"

namespace ck_tile {

template <index_t NDimSpatial,
          index_t AVectorLength,
          index_t BVectorLength,
          index_t CVectorLength,
          ConvFwdSpec Spec>
struct ConvFwdToGemmTransformer
{
    static constexpr index_t NDim = NDimSpatial + 3;

    // input tensor -> GemmA
    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<ALayout, tensor_layout::convolution::NGCHW>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeADescriptor_M_K(const std::array<index_t, NDim>& a_g_n_c_wis_lengths,
                        const std::array<index_t, NDim>& a_g_n_c_wis_strides,
                        const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */,
                        const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& /* c_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t N  = a_g_n_c_wis_lengths[1];
        const index_t C  = a_g_n_c_wis_lengths[2];
        const index_t Hi = a_g_n_c_wis_lengths[3];
        const index_t Wi = a_g_n_c_wis_lengths[4];
        const index_t Ho = c_g_n_k_wos_lengths[3];
        const index_t Wo = c_g_n_k_wos_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const auto in_n_c_hi_wi_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi),
                                         make_tuple(a_g_n_c_wis_strides[1],
                                                    a_g_n_c_wis_strides[2],
                                                    a_g_n_c_wis_strides[3],
                                                    a_g_n_c_wis_strides[4]),
                                         number<AVectorLength>{},
                                         number<1>{});

        if constexpr(Spec == ConvFwdSpec::Filter1x1Stride1Pad0)
        {

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_c_hi_wi_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_pass_through_transform(C)),
                                            make_tuple(sequence<0, 2, 3>{}, sequence<1>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else if constexpr(Spec == ConvFwdSpec::Filter1x1Pad0)
        {
            const auto in_n_c_ho_wo_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW))),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}));

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_c_ho_wo_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_pass_through_transform(C)),
                                            make_tuple(sequence<0, 2, 3>{}, sequence<1>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else
        {
            const index_t Y = b_g_k_c_xs_lengths[3];
            const index_t X = b_g_k_c_xs_lengths[4];

            const index_t ConvDilationH = conv_filter_dilations[0];
            const index_t ConvDilationW = conv_filter_dilations[1];

            const index_t InLeftPadH = input_left_pads[0];
            const index_t InLeftPadW = input_left_pads[1];

            const index_t InRightPadH = input_right_pads[0];
            const index_t InRightPadW = input_right_pads[1];

            const auto in_n_c_hip_wip_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW)),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}));

            const auto in_n_c_y_ho_x_wo_desc = transform_tensor_descriptor(
                in_n_c_hip_wip_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(C),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo),
                                         make_tuple(ConvDilationW, ConvStrideW))),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2, 3>{}, sequence<4, 5>{}));

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_c_y_ho_x_wo_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_merge_transform(make_tuple(C, Y, X))),
                                            make_tuple(sequence<0, 3, 5>{}, sequence<1, 2, 4>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
    }

    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<ALayout, tensor_layout::convolution::NHWGC>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeADescriptor_M_K(const std::array<index_t, NDim>& a_g_n_c_wis_lengths,
                        const std::array<index_t, NDim>& a_g_n_c_wis_strides,
                        const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */,
                        const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& /* c_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t N  = a_g_n_c_wis_lengths[1];
        const index_t C  = a_g_n_c_wis_lengths[2];
        const index_t Hi = a_g_n_c_wis_lengths[3];
        const index_t Wi = a_g_n_c_wis_lengths[4];
        const index_t Ho = c_g_n_k_wos_lengths[3];
        const index_t Wo = c_g_n_k_wos_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        if constexpr(Spec == ConvFwdSpec::Filter1x1Stride1Pad0)
        {
            const auto in_n_hi_wi_c_desc =
                make_naive_tensor_descriptor(make_tuple(N, Hi, Wi, C),
                                             make_tuple(a_g_n_c_wis_strides[1],
                                                        a_g_n_c_wis_strides[3],
                                                        a_g_n_c_wis_strides[4],
                                                        number<1>{}),
                                             number<AVectorLength>{},
                                             number<1>{});

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_hi_wi_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_pass_through_transform(C)),
                                            make_tuple(sequence<0, 1, 2>{}, sequence<3>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else if constexpr(Spec == ConvFwdSpec::Filter1x1Pad0)
        {
            const auto in_n_hi_wi_c_desc =
                make_naive_tensor_descriptor(make_tuple(N, Hi, Wi, C),
                                             make_tuple(a_g_n_c_wis_strides[1],
                                                        a_g_n_c_wis_strides[3],
                                                        a_g_n_c_wis_strides[4],
                                                        number<1>{}),
                                             number<AVectorLength>{},
                                             number<1>{});

            const auto in_n_ho_wo_c_desc = transform_tensor_descriptor(
                in_n_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(C)),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}));

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_ho_wo_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_pass_through_transform(C)),
                                            make_tuple(sequence<0, 1, 2>{}, sequence<3>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else
        {
            const index_t Y = b_g_k_c_xs_lengths[3];
            const index_t X = b_g_k_c_xs_lengths[4];

            const index_t ConvDilationH = conv_filter_dilations[0];
            const index_t ConvDilationW = conv_filter_dilations[1];

            const index_t InLeftPadH = input_left_pads[0];
            const index_t InLeftPadW = input_left_pads[1];

            const index_t InRightPadH = input_right_pads[0];
            const index_t InRightPadW = input_right_pads[1];

            const auto in_n_hi_wi_c_desc =
                make_naive_tensor_descriptor(make_tuple(N, Hi, Wi, C),
                                             make_tuple(a_g_n_c_wis_strides[1],
                                                        a_g_n_c_wis_strides[3],
                                                        a_g_n_c_wis_strides[4],
                                                        number<1>{}),
                                             number<AVectorLength>{},
                                             number<1>{});

            const auto in_n_hip_wip_c_desc = transform_tensor_descriptor(
                in_n_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C)),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}));

            const auto in_n_y_ho_x_wo_c_desc = transform_tensor_descriptor(
                in_n_hip_wip_c_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(C)),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}),
                make_tuple(sequence<0>{}, sequence<1, 2>{}, sequence<3, 4>{}, sequence<5>{}));

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_y_ho_x_wo_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_merge_transform(make_tuple(Y, X, C))),
                                            make_tuple(sequence<0, 2, 4>{}, sequence<1, 3, 5>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
    }

    template <
        typename ALayout,
        typename std::enable_if<
            NDimSpatial == 2 && std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, ALayout>,
            bool>::type = false>
    CK_TILE_HOST static auto
    MakeADescriptor_M_K(const std::array<index_t, NDim>& a_g_n_c_wis_lengths,
                        const std::array<index_t, NDim>& a_g_n_c_wis_strides,
                        const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */,
                        const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& /* c_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        constexpr index_t Cx = ALayout::x;

        const index_t N  = a_g_n_c_wis_lengths[1];
        const index_t C  = a_g_n_c_wis_lengths[2];
        const index_t Hi = a_g_n_c_wis_lengths[3];
        const index_t Wi = a_g_n_c_wis_lengths[4];
        const index_t Ho = c_g_n_k_wos_lengths[3];
        const index_t Wo = c_g_n_k_wos_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const auto in_n_c_hi_wi_c_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi, Cx),
                                         make_tuple(a_g_n_c_wis_strides[1],
                                                    a_g_n_c_wis_strides[2],
                                                    a_g_n_c_wis_strides[3],
                                                    a_g_n_c_wis_strides[4],
                                                    number<1>{}),
                                         number<AVectorLength>{},
                                         number<1>{});

        if constexpr(Spec == ConvFwdSpec::Filter1x1Stride1Pad0)
        {

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_c_hi_wi_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_merge_transform(make_tuple(C, Cx))),
                                            make_tuple(sequence<0, 2, 3>{}, sequence<1, 4>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else if constexpr(Spec == ConvFwdSpec::Filter1x1Pad0)
        {
            const auto in_n_c_ho_wo_c_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(Cx)),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}));

            const auto in_gemmm_gemmk_desc =
                transform_tensor_descriptor(in_n_c_ho_wo_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_merge_transform(make_tuple(C, Cx))),
                                            make_tuple(sequence<0, 2, 3>{}, sequence<1, 4>{}),
                                            make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else
        {
            const index_t Y = b_g_k_c_xs_lengths[3];
            const index_t X = b_g_k_c_xs_lengths[4];

            const index_t ConvDilationH = conv_filter_dilations[0];
            const index_t ConvDilationW = conv_filter_dilations[1];

            const index_t InLeftPadH = input_left_pads[0];
            const index_t InLeftPadW = input_left_pads[1];

            const index_t InRightPadH = input_right_pads[0];
            const index_t InRightPadW = input_right_pads[1];

            const auto in_n_c_hip_wip_c_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(Cx)),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}));

            const auto in_n_c_y_ho_x_wo_c_desc = transform_tensor_descriptor(
                in_n_c_hip_wip_c_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(C),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(Cx)),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}),
                make_tuple(sequence<0>{},
                           sequence<1>{},
                           sequence<2, 3>{},
                           sequence<4, 5>{},
                           sequence<6>{}));

            const auto in_gemmm_gemmk_desc = transform_tensor_descriptor(
                in_n_c_y_ho_x_wo_c_desc,
                make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                           make_merge_transform(make_tuple(C, Y, X, Cx))),
                make_tuple(sequence<0, 3, 5>{}, sequence<1, 2, 4, 6>{}),
                make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
    }

    // weight tensor -> GemmB
    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<BLayout, tensor_layout::convolution::GKCYX>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */)
    {
        const index_t K = b_g_k_c_xs_lengths[1];
        const index_t C = b_g_k_c_xs_lengths[2];
        const index_t Y = b_g_k_c_xs_lengths[3];
        const index_t X = b_g_k_c_xs_lengths[4];

        const auto wei_k_c_y_x_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, C, Y, X), number<BVectorLength>{});

        const auto wei_gemmn_gemmk_desc = transform_tensor_descriptor(
            wei_k_c_y_x_desc,
            make_tuple(make_merge_transform(make_tuple(C, Y, X)), make_pass_through_transform(K)),
            make_tuple(sequence<1, 2, 3>{}, sequence<0>{}),
            make_tuple(sequence<1>{}, sequence<0>{}));

        return wei_gemmn_gemmk_desc;
    }

    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<BLayout, tensor_layout::convolution::GKYXC>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */)
    {
        const index_t K = b_g_k_c_xs_lengths[1];
        const index_t Y = b_g_k_c_xs_lengths[3];
        const index_t X = b_g_k_c_xs_lengths[4];
        const index_t C = b_g_k_c_xs_lengths[2];

        const auto wei_k_y_x_c_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, Y, X, C), number<BVectorLength>{});

        const auto wei_gemmn_gemmk_desc = transform_tensor_descriptor(
            wei_k_y_x_c_desc,
            make_tuple(make_pass_through_transform(K), make_merge_transform(make_tuple(Y, X, C))),
            make_tuple(sequence<0>{}, sequence<1, 2, 3>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));

        return wei_gemmn_gemmk_desc;
    }

    template <
        typename BLayout,
        typename std::enable_if<
            NDimSpatial == 2 && std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, BLayout>,
            bool>::type = false>
    CK_TILE_HOST static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */)
    {
        constexpr index_t Cx = BLayout::x;

        const index_t K = b_g_k_c_xs_lengths[1];
        const index_t C = b_g_k_c_xs_lengths[2];
        const index_t Y = b_g_k_c_xs_lengths[3];
        const index_t X = b_g_k_c_xs_lengths[4];

        const auto wei_k_c_y_x_c_desc = make_naive_tensor_descriptor_packed(
            make_tuple(K, C, Y, X, Cx), number<BVectorLength>{});

        const auto wei_gemmn_gemmk_desc =
            transform_tensor_descriptor(wei_k_c_y_x_c_desc,
                                        make_tuple(make_merge_transform(make_tuple(C, Y, X, Cx)),
                                                   make_pass_through_transform(K)),
                                        make_tuple(sequence<1, 2, 3, 4>{}, sequence<0>{}),
                                        make_tuple(sequence<1>{}, sequence<0>{}));

        return wei_gemmn_gemmk_desc;
    }

    // output tensor -> GemmC
    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<CLayout, tensor_layout::convolution::NGKHW>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& c_g_n_k_wos_strides)
    {
        const index_t N  = c_g_n_k_wos_lengths[1];
        const index_t K  = c_g_n_k_wos_lengths[2];
        const index_t Ho = c_g_n_k_wos_lengths[3];
        const index_t Wo = c_g_n_k_wos_lengths[4];

        const auto out_n_k_ho_wo_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo),
                                         make_tuple(c_g_n_k_wos_strides[1],
                                                    c_g_n_k_wos_strides[2],
                                                    c_g_n_k_wos_strides[3],
                                                    c_g_n_k_wos_strides[4]),
                                         number<CVectorLength>{},
                                         number<1>{});

        const auto out_gemmm_gemmn_desc = transform_tensor_descriptor(
            out_n_k_ho_wo_desc,
            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)), make_pass_through_transform(K)),
            make_tuple(sequence<0, 2, 3>{}, sequence<1>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));

        return out_gemmm_gemmn_desc;
    }

    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && std::is_same_v<CLayout, tensor_layout::convolution::NHWGK>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& c_g_n_k_wos_strides)
    {
        const index_t N  = c_g_n_k_wos_lengths[1];
        const index_t Ho = c_g_n_k_wos_lengths[3];
        const index_t Wo = c_g_n_k_wos_lengths[4];
        const index_t K  = c_g_n_k_wos_lengths[2];

        const index_t NHoWo = N * Ho * Wo;

        const auto out_gemmm_gemmn_desc =
            make_naive_tensor_descriptor(make_tuple(NHoWo, K),
                                         make_tuple(c_g_n_k_wos_strides[4], number<1>{}),
                                         number<CVectorLength>{},
                                         number<1>{});

        return out_gemmm_gemmn_desc;
    }

    template <
        typename CLayout,
        typename std::enable_if<
            NDimSpatial == 2 && std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, CLayout>,
            bool>::type = false>
    CK_TILE_HOST static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& c_g_n_k_wos_strides)
    {
        constexpr index_t Kx = CLayout::x;

        const index_t N  = c_g_n_k_wos_lengths[1];
        const index_t K  = c_g_n_k_wos_lengths[2];
        const index_t Ho = c_g_n_k_wos_lengths[3];
        const index_t Wo = c_g_n_k_wos_lengths[4];

        const auto out_n_k_ho_wo_k_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo, Kx),
                                         make_tuple(c_g_n_k_wos_strides[1],
                                                    c_g_n_k_wos_strides[2],
                                                    c_g_n_k_wos_strides[3],
                                                    c_g_n_k_wos_strides[4],
                                                    number<1>{}),
                                         number<CVectorLength>{},
                                         number<1>{});

        const auto out_gemmm_gemmn_desc =
            transform_tensor_descriptor(out_n_k_ho_wo_k_desc,
                                        make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                   make_merge_transform(make_tuple(K, Kx))),
                                        make_tuple(sequence<0, 2, 3>{}, sequence<1, 4>{}),
                                        make_tuple(sequence<0>{}, sequence<1>{}));

        return out_gemmm_gemmn_desc;
    }
};

} // namespace ck_tile
