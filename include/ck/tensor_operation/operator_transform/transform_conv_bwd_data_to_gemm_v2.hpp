// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_data_specialization.hpp"

namespace ck {
namespace tensor_operation {

template <
    index_t NDimSpatial,
    ck::tensor_operation::device::ConvolutionBackwardDataSpecialization ConvBwdDataSpecialization>
struct TransformConvBwdDataToGemm_v2
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};

    template <typename ALayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<ALayout, tensor_layout::convolution::GNHWK> ||
                                           is_same_v<ALayout, tensor_layout::convolution::NHWGK>),
                                      bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t N = in_g_n_c_wis_lengths[1];
        const index_t K = wei_g_k_c_xs_lengths[1];

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume packed
        const auto out_n_ho_wo_k_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, Ho, Wo, K),
                                         make_tuple(out_g_n_k_wos_strides[1],
                                                    out_g_n_k_wos_strides[3],
                                                    out_g_n_k_wos_strides[4],
                                                    out_g_n_k_wos_strides[2]));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // A: output tensor
            const auto out_gemmmraw_gemmkraw_grid_desc =
                transform_tensor_descriptor(out_n_ho_wo_k_grid_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_pass_through_transform(K)),
                                            make_tuple(Sequence<0, 1, 2>{}, Sequence<3>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // A: output tensor
            const auto out_n_hop_wop_k_grid_desc = transform_tensor_descriptor(
                out_n_ho_wo_k_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pad_transform(Ho, I0, I0),
                           make_pad_transform(Wo, I0, I0),
                           make_pass_through_transform(K)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto out_n_ydot_htilde_xdot_wtilde_k_grid_desc = transform_tensor_descriptor(
                out_n_hop_wop_k_grid_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_embed_transform(make_tuple(YDot, HTilde),
                                         make_tuple(-ConvDilationH / GcdStrideDilationH, I1)),
                    make_embed_transform(make_tuple(XDot, WTilde),
                                         make_tuple(-ConvDilationW / GcdStrideDilationW, I1)),
                    make_pass_through_transform(K)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3, 4>{}, Sequence<5>{}));

            const auto out_n_ydotslice_htildeslice_xdotslice_wtildeslice_k_grid_desc =
                transform_tensor_descriptor(
                    out_n_ydot_htilde_xdot_wtilde_k_grid_desc,
                    make_tuple(make_pass_through_transform(N),
                               make_slice_transform(YDot, I0, YDotSlice),
                               make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                               make_slice_transform(XDot, I0, XDotSlice),
                               make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice),
                               make_pass_through_transform(K)),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}));

            const auto out_gemmmraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                out_n_ydotslice_htildeslice_xdotslice_wtildeslice_k_grid_desc,
                make_tuple(make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice)),
                           make_merge_transform(make_tuple(YDotSlice, XDotSlice, K))),
                make_tuple(Sequence<0, 2, 4>{}, Sequence<1, 3, 5>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
    }

    template <typename ALayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<ALayout, tensor_layout::convolution::GNKHW> ||
                                           is_same_v<ALayout, tensor_layout::convolution::NGKHW>),
                                      bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t N = in_g_n_c_wis_lengths[1];
        const index_t K = wei_g_k_c_xs_lengths[1];

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume packed
        const auto out_n_k_ho_wo_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo),
                                         make_tuple(out_g_n_k_wos_strides[1],
                                                    out_g_n_k_wos_strides[2],
                                                    out_g_n_k_wos_strides[3],
                                                    out_g_n_k_wos_strides[4]));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // A: output tensor
            const auto out_gemmmraw_gemmkraw_grid_desc =
                transform_tensor_descriptor(out_n_k_ho_wo_grid_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_pass_through_transform(K)),
                                            make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // A: output tensor
            const auto out_n_k_hop_wop_grid_desc = transform_tensor_descriptor(
                out_n_k_ho_wo_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(K),
                           make_pad_transform(Ho, I0, I0),
                           make_pad_transform(Wo, I0, I0)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto out_n_k_ydot_htilde_xdot_wtilde_grid_desc = transform_tensor_descriptor(
                out_n_k_hop_wop_grid_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(K),
                    make_embed_transform(make_tuple(YDot, HTilde),
                                         make_tuple(-ConvDilationH / GcdStrideDilationH, I1)),
                    make_embed_transform(make_tuple(XDot, WTilde),
                                         make_tuple(-ConvDilationW / GcdStrideDilationW, I1))),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2, 3>{}, Sequence<4, 5>{}));

            const auto out_n_k_ydotslice_htildeslice_xdotslice_wtildeslice_grid_desc =
                transform_tensor_descriptor(
                    out_n_k_ydot_htilde_xdot_wtilde_grid_desc,
                    make_tuple(make_pass_through_transform(N),
                               make_pass_through_transform(K),
                               make_slice_transform(YDot, I0, YDotSlice),
                               make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                               make_slice_transform(XDot, I0, XDotSlice),
                               make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice)),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}));

            const auto out_gemmmraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                out_n_k_ydotslice_htildeslice_xdotslice_wtildeslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice)),
                           make_merge_transform(make_tuple(K, YDotSlice, XDotSlice))),
                make_tuple(Sequence<0, 3, 5>{}, Sequence<1, 2, 4>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
    }

    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          is_same_v<BLayout, tensor_layout::convolution::GKYXC>,
                                      bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t K = wei_g_k_c_xs_lengths[1];
        const index_t C = wei_g_k_c_xs_lengths[2];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume packed
        const auto wei_k_y_x_c_grid_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, Y, X, C));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // B: weight tensor
            const auto wei_gemmnraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                make_naive_tensor_descriptor_packed(make_tuple(K, C)),
                make_tuple(make_pass_through_transform(K), make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // B weight tensor
            const auto wei_k_ydot_ytilde_xdot_xtilde_c_grid_desc = transform_tensor_descriptor(
                wei_k_y_x_c_grid_desc,
                make_tuple(make_pass_through_transform(K),
                           make_embed_transform(make_tuple(YDot, YTilde),
                                                make_tuple(ConvStrideH / GcdStrideDilationH, I1)),
                           make_embed_transform(make_tuple(XDot, XTilde),
                                                make_tuple(ConvStrideW / GcdStrideDilationW, I1)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3, 4>{}, Sequence<5>{}));

            const auto wei_k_ydotslice_xdotslice_c_grid_desc =
                transform_tensor_descriptor(wei_k_ydot_ytilde_xdot_xtilde_c_grid_desc,
                                            make_tuple(make_pass_through_transform(K),
                                                       make_slice_transform(YDot, I0, YDotSlice),
                                                       make_slice_transform(XDot, I0, XDotSlice),
                                                       make_freeze_transform(i_ytilde),
                                                       make_freeze_transform(i_xtilde),
                                                       make_pass_through_transform(C)),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<3>{},
                                                       Sequence<2>{},
                                                       Sequence<4>{},
                                                       Sequence<5>{}),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<>{},
                                                       Sequence<>{},
                                                       Sequence<3>{}));

            const auto wei_gemmnraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                wei_k_ydotslice_xdotslice_c_grid_desc,
                make_tuple(make_merge_transform(make_tuple(YDotSlice, XDotSlice, K)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<1, 2, 0>{}, Sequence<3>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
    }

    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          is_same_v<BLayout, tensor_layout::convolution::GKCYX>,
                                      bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t K = wei_g_k_c_xs_lengths[1];
        const index_t C = wei_g_k_c_xs_lengths[2];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume packed
        const auto wei_k_c_y_x_grid_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, C, Y, X));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // B: weight tensor
            const auto wei_gemmnraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                make_naive_tensor_descriptor_packed(make_tuple(K, C)),
                make_tuple(make_pass_through_transform(K), make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // B weight tensor
            const auto wei_k_c_ydot_ytilde_xdot_xtilde_grid_desc = transform_tensor_descriptor(
                wei_k_c_y_x_grid_desc,
                make_tuple(make_pass_through_transform(K),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(YDot, YTilde),
                                                make_tuple(ConvStrideH / GcdStrideDilationH, I1)),
                           make_embed_transform(make_tuple(XDot, XTilde),
                                                make_tuple(ConvStrideW / GcdStrideDilationW, I1))),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2, 3>{}, Sequence<4, 5>{}));

            const auto wei_k_c_ydotslice_xdotslice_grid_desc =
                transform_tensor_descriptor(wei_k_c_ydot_ytilde_xdot_xtilde_grid_desc,
                                            make_tuple(make_pass_through_transform(K),
                                                       make_pass_through_transform(C),
                                                       make_slice_transform(YDot, I0, YDotSlice),
                                                       make_slice_transform(XDot, I0, XDotSlice),
                                                       make_freeze_transform(i_ytilde),
                                                       make_freeze_transform(i_xtilde)),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<4>{},
                                                       Sequence<3>{},
                                                       Sequence<5>{}),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<>{},
                                                       Sequence<>{}));

            const auto wei_gemmnraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                wei_k_c_ydotslice_xdotslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(K, YDotSlice, XDotSlice)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
    }

    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<CLayout, tensor_layout::convolution::GNHWC> ||
                                           is_same_v<CLayout, tensor_layout::convolution::NHWGC> ||
                                           is_same_v<CLayout, tensor_layout::convolution::G_NHW_C>),
                                      bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t N = in_g_n_c_wis_lengths[1];
        const index_t C = wei_g_k_c_xs_lengths[2];

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume strided
        const auto in_n_hi_wi_c_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, Hi, Wi, C),
                                         make_tuple(in_g_n_c_wis_strides[1],
                                                    in_g_n_c_wis_strides[3],
                                                    in_g_n_c_wis_strides[4],
                                                    in_g_n_c_wis_strides[2]));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // C: input tensor
            const auto in_n_y_ho_x_wo_c_grid_desc = transform_tensor_descriptor(
                in_n_hi_wi_c_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_embed_transform(make_tuple(I1, Ho), make_tuple(I1, ConvStrideH)),
                           make_embed_transform(make_tuple(I1, Wo), make_tuple(I1, ConvStrideW)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3, 4>{}, Sequence<5>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_y_ho_x_wo_c_grid_desc,
                make_tuple(make_freeze_transform(I0),
                           make_freeze_transform(I0),
                           make_merge_transform(make_tuple(N, Ho, Wo)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<1>{}, Sequence<3>{}, Sequence<0, 2, 4>{}, Sequence<5>{}),
                make_tuple(Sequence<>{}, Sequence<>{}, Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // C: input tensor
            const auto in_n_hip_wip_c_grid_desc = transform_tensor_descriptor(
                in_n_hi_wi_c_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto in_n_ytilde_htilde_xtilde_wtilde_c_grid_desc = transform_tensor_descriptor(
                in_n_hip_wip_c_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_embed_transform(make_tuple(YTilde, HTilde),
                                                make_tuple(ConvDilationH, ConvStrideH)),
                           make_embed_transform(make_tuple(XTilde, WTilde),
                                                make_tuple(ConvDilationW, ConvStrideW)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3, 4>{}, Sequence<5>{}));

            const auto in_n_htildeslice_wtildeslice_c_grid_desc = transform_tensor_descriptor(
                in_n_ytilde_htilde_xtilde_wtilde_c_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_freeze_transform(i_ytilde),
                           make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                           make_freeze_transform(i_xtilde),
                           make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{}),
                make_tuple(Sequence<0>{},
                           Sequence<>{},
                           Sequence<1>{},
                           Sequence<>{},
                           Sequence<2>{},
                           Sequence<3>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_htildeslice_wtildeslice_c_grid_desc,
                make_tuple(make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0, 1, 2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
    }

    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<CLayout, tensor_layout::convolution::GNCHW> ||
                                           is_same_v<CLayout, tensor_layout::convolution::NGCHW>),
                                      bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t N = in_g_n_c_wis_lengths[1];
        const index_t C = in_g_n_c_wis_lengths[2];

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume strided
        const auto in_n_c_hi_wi_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi),
                                         make_tuple(in_g_n_c_wis_strides[1],
                                                    in_g_n_c_wis_strides[2],
                                                    in_g_n_c_wis_strides[3],
                                                    in_g_n_c_wis_strides[4]));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // C: input tensor
            const auto in_n_c_y_ho_x_wo_grid_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(I1, Ho), make_tuple(I1, ConvStrideH)),
                           make_embed_transform(make_tuple(I1, Wo), make_tuple(I1, ConvStrideW))),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2, 3>{}, Sequence<4, 5>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_c_y_ho_x_wo_grid_desc,
                make_tuple(make_freeze_transform(I0),
                           make_freeze_transform(I0),
                           make_merge_transform(make_tuple(N, Ho, Wo)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<2>{}, Sequence<4>{}, Sequence<0, 3, 5>{}, Sequence<1>{}),
                make_tuple(Sequence<>{}, Sequence<>{}, Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // C: input tensor
            const auto in_n_c_hip_wip_grid_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto in_n_c_ytilde_htilde_xtilde_wtilde_grid_desc = transform_tensor_descriptor(
                in_n_c_hip_wip_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(YTilde, HTilde),
                                                make_tuple(ConvDilationH, ConvStrideH)),
                           make_embed_transform(make_tuple(XTilde, WTilde),
                                                make_tuple(ConvDilationW, ConvStrideW))),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2, 3>{}, Sequence<4, 5>{}));

            const auto in_n_c_htildeslice_wtildeslice_grid_desc = transform_tensor_descriptor(
                in_n_c_ytilde_htilde_xtilde_wtilde_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_freeze_transform(i_ytilde),
                           make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                           make_freeze_transform(i_xtilde),
                           make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice)),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<>{},
                           Sequence<2>{},
                           Sequence<>{},
                           Sequence<3>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_c_htildeslice_wtildeslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
    }

#if 0
    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 && (is_same_v<ALayout, tensor_layout::convolution::NGKHWk32>),
                  bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t K_VECT = 32;

        const index_t N       = in_g_n_c_wis_lengths[1];
        const index_t K_TOTAL = wei_g_k_c_xs_lengths[1];
        const index_t K       = K_TOTAL / K_VECT;

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const auto out_n_k_ho_wo_k32_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo, K_VECT),
                                         make_tuple(out_g_n_k_wos_strides[1],
                                                    out_g_n_k_wos_strides[2],
                                                    out_g_n_k_wos_strides[3],
                                                    out_g_n_k_wos_strides[4],
                                                    1));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // A: output tensor
            const auto out_n_ktotal_ho_wo_grid_desc = transform_tensor_descriptor(
                out_n_k_ho_wo_k32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_merge_transform(make_tuple(K, K_VECT)),
                           make_pass_through_transform(Ho),
                           make_pass_through_transform(Wo)),
                make_tuple(Sequence<0>{}, Sequence<1, 4>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto out_gemmmraw_gemmkraw_grid_desc =
                transform_tensor_descriptor(out_n_ktotal_ho_wo_grid_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_pass_through_transform(K_TOTAL)),
                                            make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // A: output tensor
            const auto out_n_k_hop_wop_k32_grid_desc = transform_tensor_descriptor(
                out_n_k_ho_wo_k32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(K),
                           make_pad_transform(Ho, I0, I0),
                           make_pad_transform(Wo, I0, I0),
                           make_pass_through_transform(K_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto out_n_k_ydot_htilde_xdot_wtilde_k32_grid_desc = transform_tensor_descriptor(
                out_n_k_hop_wop_k32_grid_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(K),
                    make_embed_transform(make_tuple(YDot, HTilde),
                                         make_tuple(-ConvDilationH / GcdStrideDilationH, I1)),
                    make_embed_transform(make_tuple(XDot, WTilde),
                                         make_tuple(-ConvDilationW / GcdStrideDilationW, I1)),
                    make_pass_through_transform(K_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2, 3>{},
                           Sequence<4, 5>{},
                           Sequence<6>{}));

            const auto out_n_ktotal_ydot_htilde_xdot_wtilde_grid_desc =
                transform_tensor_descriptor(out_n_k_ydot_htilde_xdot_wtilde_k32_grid_desc,
                                            make_tuple(make_pass_through_transform(N),
                                                       make_merge_transform(make_tuple(K, K_VECT)),
                                                       make_pass_through_transform(YDot),
                                                       make_pass_through_transform(HTilde),
                                                       make_pass_through_transform(XDot),
                                                       make_pass_through_transform(WTilde)),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1, 6>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<4>{},
                                                       Sequence<5>{}),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<4>{},
                                                       Sequence<5>{}));

            const auto out_n_ktotal_ydotslice_htildeslice_xdotslice_wtildeslice_grid_desc =
                transform_tensor_descriptor(
                    out_n_ktotal_ydot_htilde_xdot_wtilde_grid_desc,
                    make_tuple(make_pass_through_transform(N),
                               make_pass_through_transform(K_TOTAL),
                               make_slice_transform(YDot, I0, YDotSlice),
                               make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                               make_slice_transform(XDot, I0, XDotSlice),
                               make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice)),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}));

            const auto out_gemmmraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                out_n_ktotal_ydotslice_htildeslice_xdotslice_wtildeslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(YDotSlice, XDotSlice, K_TOTAL)),
                           make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice))),
                make_tuple(Sequence<2, 4, 1>{}, Sequence<0, 3, 5>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
    }

    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          is_same_v<BLayout, tensor_layout::convolution::GKCYXc32>,
                                      bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t C_VECT  = 32;
        const index_t C       = wei_g_k_c_xs_lengths[2];
        const index_t C_TOTAL = C * C_VECT;

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const index_t K_TOTAL = wei_g_k_c_xs_lengths[1];

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // B: weight tensor
            const auto wei_ktotal_ctotal_grid_desc =
                make_naive_tensor_descriptor_packed(make_tuple(K_TOTAL, C_TOTAL));

            const auto wei_gemmnraw_gemmkraw_grid_desc =
                transform_tensor_descriptor(wei_ktotal_ctotal_grid_desc,
                                            make_tuple(make_pass_through_transform(C_TOTAL),
                                                       make_pass_through_transform(K_TOTAL)),
                                            make_tuple(Sequence<1>{}, Sequence<0>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
        else
        {
            // assume packed
            const auto wei_ktotal_c_y_x_c32_grid_desc =
                make_naive_tensor_descriptor_packed(make_tuple(K_TOTAL, C, Y, X, C_VECT));

            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // B weight tensor
            const auto wei_ktotal_c_ydot_ytilde_xdot_xtilde_c32_grid_desc =
                transform_tensor_descriptor(
                    wei_ktotal_c_y_x_c32_grid_desc,
                    make_tuple(
                        make_pass_through_transform(K_TOTAL),
                        make_pass_through_transform(C),
                        make_embed_transform(make_tuple(YDot, YTilde),
                                             make_tuple(ConvStrideH / GcdStrideDilationH, I1)),
                        make_embed_transform(make_tuple(XDot, XTilde),
                                             make_tuple(ConvStrideW / GcdStrideDilationW, I1)),
                        make_pass_through_transform(C_VECT)),
                    make_tuple(
                        Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2, 3>{},
                               Sequence<4, 5>{},
                               Sequence<6>{}));

            const auto wei_ktotal_ctotal_ydotslice_xdotslice_grid_desc =
                transform_tensor_descriptor(wei_ktotal_c_ydot_ytilde_xdot_xtilde_c32_grid_desc,
                                            make_tuple(make_pass_through_transform(K_TOTAL),
                                                       make_merge_transform(make_tuple(C, C_VECT)),
                                                       make_slice_transform(YDot, I0, YDotSlice),
                                                       make_slice_transform(XDot, I0, XDotSlice),
                                                       make_freeze_transform(i_ytilde),
                                                       make_freeze_transform(i_xtilde)),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1, 6>{},
                                                       Sequence<2>{},
                                                       Sequence<4>{},
                                                       Sequence<3>{},
                                                       Sequence<5>{}),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<>{},
                                                       Sequence<>{}));

            const auto wei_gemmnraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                wei_ktotal_ctotal_ydotslice_xdotslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(YDotSlice, XDotSlice, K_TOTAL)),
                           make_pass_through_transform(C_TOTAL)),
                make_tuple(Sequence<2, 3, 0>{}, Sequence<1>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
    }

    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && (is_same_v<CLayout, tensor_layout::convolution::NGCHWc32>),
                  bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t C_VECT = 32;
        const index_t N      = in_g_n_c_wis_lengths[1];
        const index_t C      = wei_g_k_c_xs_lengths[2];

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume strided
        const auto in_n_c_hi_wi_c32_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi, C_VECT),
                                         make_tuple(in_g_n_c_wis_strides[1],
                                                    in_g_n_c_wis_strides[2],
                                                    in_g_n_c_wis_strides[3],
                                                    in_g_n_c_wis_strides[4],
                                                    1));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // C: input tensor
            const auto in_n_c_y_ho_x_wo_c32_grid_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(I1, Ho), make_tuple(I1, ConvStrideH)),
                           make_embed_transform(make_tuple(I1, Wo), make_tuple(I1, ConvStrideW)),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2, 3>{},
                           Sequence<4, 5>{},
                           Sequence<6>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_c_y_ho_x_wo_c32_grid_desc,
                make_tuple(make_freeze_transform(I0),
                           make_freeze_transform(I0),
                           make_merge_transform(make_tuple(N, Ho, Wo)),
                           make_merge_transform(make_tuple(C, C_VECT))),
                make_tuple(Sequence<2>{}, Sequence<4>{}, Sequence<0, 3, 5>{}, Sequence<1, 6>{}),
                make_tuple(Sequence<>{}, Sequence<>{}, Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // C: input tensor
            const auto in_n_c_hip_wip_c32_grid_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_n_c_ytilde_htilde_xtilde_wtilde_c32_grid_desc =
                transform_tensor_descriptor(
                    in_n_c_hip_wip_c32_grid_desc,
                    make_tuple(make_pass_through_transform(N),
                               make_pass_through_transform(C),
                               make_embed_transform(make_tuple(YTilde, HTilde),
                                                    make_tuple(ConvDilationH, ConvStrideH)),
                               make_embed_transform(make_tuple(XTilde, WTilde),
                                                    make_tuple(ConvDilationW, ConvStrideW)),
                               make_pass_through_transform(C_VECT)),
                    make_tuple(
                        Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2, 3>{},
                               Sequence<4, 5>{},
                               Sequence<6>{}));

            const auto in_n_c_htildeslice_wtildeslice_c32_grid_desc = transform_tensor_descriptor(
                in_n_c_ytilde_htilde_xtilde_wtilde_c32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_freeze_transform(i_ytilde),
                           make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                           make_freeze_transform(i_xtilde),
                           make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice),
                           make_pass_through_transform(C_VECT)),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<>{},
                           Sequence<2>{},
                           Sequence<>{},
                           Sequence<3>{},
                           Sequence<4>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_c_htildeslice_wtildeslice_c32_grid_desc,
                make_tuple(make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice)),
                           make_merge_transform(make_tuple(C, C_VECT))),
                make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
    }
#endif

    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 &&
                      (std::is_base_of_v<ck::tensor_layout::convolution::NGCHWcBase, ALayout>),
                  bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t K_VECT = ALayout::x;

        const index_t N       = in_g_n_c_wis_lengths[1];
        const index_t K_TOTAL = wei_g_k_c_xs_lengths[1];
        const index_t K       = K_TOTAL / K_VECT;

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const auto out_n_k_ho_wo_k32_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo, K_VECT),
                                         make_tuple(out_g_n_k_wos_strides[1],
                                                    out_g_n_k_wos_strides[2],
                                                    out_g_n_k_wos_strides[3],
                                                    out_g_n_k_wos_strides[4],
                                                    1));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // A: output tensor
            const auto out_n_ktotal_ho_wo_grid_desc = transform_tensor_descriptor(
                out_n_k_ho_wo_k32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_merge_transform(make_tuple(K, K_VECT)),
                           make_pass_through_transform(Ho),
                           make_pass_through_transform(Wo)),
                make_tuple(Sequence<0>{}, Sequence<1, 4>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto out_gemmmraw_gemmkraw_grid_desc =
                transform_tensor_descriptor(out_n_ktotal_ho_wo_grid_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                       make_pass_through_transform(K_TOTAL)),
                                            make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // A: output tensor
            const auto out_n_k_hop_wop_k32_grid_desc = transform_tensor_descriptor(
                out_n_k_ho_wo_k32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(K),
                           make_pad_transform(Ho, I0, I0),
                           make_pad_transform(Wo, I0, I0),
                           make_pass_through_transform(K_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto out_n_k_ydot_htilde_xdot_wtilde_k32_grid_desc = transform_tensor_descriptor(
                out_n_k_hop_wop_k32_grid_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(K),
                    make_embed_transform(make_tuple(YDot, HTilde),
                                         make_tuple(-ConvDilationH / GcdStrideDilationH, I1)),
                    make_embed_transform(make_tuple(XDot, WTilde),
                                         make_tuple(-ConvDilationW / GcdStrideDilationW, I1)),
                    make_pass_through_transform(K_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2, 3>{},
                           Sequence<4, 5>{},
                           Sequence<6>{}));

            const auto out_n_ktotal_ydot_htilde_xdot_wtilde_grid_desc =
                transform_tensor_descriptor(out_n_k_ydot_htilde_xdot_wtilde_k32_grid_desc,
                                            make_tuple(make_pass_through_transform(N),
                                                       make_merge_transform(make_tuple(K, K_VECT)),
                                                       make_pass_through_transform(YDot),
                                                       make_pass_through_transform(HTilde),
                                                       make_pass_through_transform(XDot),
                                                       make_pass_through_transform(WTilde)),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1, 6>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<4>{},
                                                       Sequence<5>{}),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<4>{},
                                                       Sequence<5>{}));

            const auto out_n_ktotal_ydotslice_htildeslice_xdotslice_wtildeslice_grid_desc =
                transform_tensor_descriptor(
                    out_n_ktotal_ydot_htilde_xdot_wtilde_grid_desc,
                    make_tuple(make_pass_through_transform(N),
                               make_pass_through_transform(K_TOTAL),
                               make_slice_transform(YDot, I0, YDotSlice),
                               make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                               make_slice_transform(XDot, I0, XDotSlice),
                               make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice)),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2>{},
                               Sequence<3>{},
                               Sequence<4>{},
                               Sequence<5>{}));

            const auto out_gemmmraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                out_n_ktotal_ydotslice_htildeslice_xdotslice_wtildeslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(YDotSlice, XDotSlice, K_TOTAL)),
                           make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice))),
                make_tuple(Sequence<2, 4, 1>{}, Sequence<0, 3, 5>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return out_gemmmraw_gemmkraw_grid_desc;
        }
    }

    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 2 &&
                      std::is_base_of_v<ck::tensor_layout::convolution::GKCYXcBase, BLayout>,
                  bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* in_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t C_VECT  = BLayout::x;
        const index_t C       = wei_g_k_c_xs_lengths[2];
        const index_t C_TOTAL = C * C_VECT;

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const index_t K_TOTAL = wei_g_k_c_xs_lengths[1];

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // B: weight tensor
            const auto wei_ktotal_ctotal_grid_desc =
                make_naive_tensor_descriptor_packed(make_tuple(K_TOTAL, C_TOTAL));

            const auto wei_gemmnraw_gemmkraw_grid_desc =
                transform_tensor_descriptor(wei_ktotal_ctotal_grid_desc,
                                            make_tuple(make_pass_through_transform(C_TOTAL),
                                                       make_pass_through_transform(K_TOTAL)),
                                            make_tuple(Sequence<1>{}, Sequence<0>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
        else
        {
            // assume packed
            const auto wei_ktotal_c_y_x_c32_grid_desc =
                make_naive_tensor_descriptor_packed(make_tuple(K_TOTAL, C, Y, X, C_VECT));

            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto YDot = math::integer_divide_ceil(Y, YTilde);
            const auto XDot = math::integer_divide_ceil(X, XTilde);

            // GemmK is different for each GEMM
            const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
            const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

            // B weight tensor
            const auto wei_ktotal_c_ydot_ytilde_xdot_xtilde_c32_grid_desc =
                transform_tensor_descriptor(
                    wei_ktotal_c_y_x_c32_grid_desc,
                    make_tuple(
                        make_pass_through_transform(K_TOTAL),
                        make_pass_through_transform(C),
                        make_embed_transform(make_tuple(YDot, YTilde),
                                             make_tuple(ConvStrideH / GcdStrideDilationH, I1)),
                        make_embed_transform(make_tuple(XDot, XTilde),
                                             make_tuple(ConvStrideW / GcdStrideDilationW, I1)),
                        make_pass_through_transform(C_VECT)),
                    make_tuple(
                        Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2, 3>{},
                               Sequence<4, 5>{},
                               Sequence<6>{}));

            const auto wei_ktotal_ctotal_ydotslice_xdotslice_grid_desc =
                transform_tensor_descriptor(wei_ktotal_c_ydot_ytilde_xdot_xtilde_c32_grid_desc,
                                            make_tuple(make_pass_through_transform(K_TOTAL),
                                                       make_merge_transform(make_tuple(C, C_VECT)),
                                                       make_slice_transform(YDot, I0, YDotSlice),
                                                       make_slice_transform(XDot, I0, XDotSlice),
                                                       make_freeze_transform(i_ytilde),
                                                       make_freeze_transform(i_xtilde)),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1, 6>{},
                                                       Sequence<2>{},
                                                       Sequence<4>{},
                                                       Sequence<3>{},
                                                       Sequence<5>{}),
                                            make_tuple(Sequence<0>{},
                                                       Sequence<1>{},
                                                       Sequence<2>{},
                                                       Sequence<3>{},
                                                       Sequence<>{},
                                                       Sequence<>{}));

            const auto wei_gemmnraw_gemmkraw_grid_desc = transform_tensor_descriptor(
                wei_ktotal_ctotal_ydotslice_xdotslice_grid_desc,
                make_tuple(make_merge_transform(make_tuple(YDotSlice, XDotSlice, K_TOTAL)),
                           make_pass_through_transform(C_TOTAL)),
                make_tuple(Sequence<2, 3, 0>{}, Sequence<1>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));

            return wei_gemmnraw_gemmkraw_grid_desc;
        }
    }

    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 2 &&
                      (std::is_base_of_v<ck::tensor_layout::convolution::NGCHWcBase, CLayout>),
                  bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* out_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* wei_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads,
                        index_t i_ytilde,
                        index_t i_xtilde)
    {
        const index_t C_VECT = CLayout::x;
        const index_t N      = in_g_n_c_wis_lengths[1];
        const index_t C      = wei_g_k_c_xs_lengths[2];

        const index_t Hi = in_g_n_c_wis_lengths[3];
        const index_t Wi = in_g_n_c_wis_lengths[4];

        const index_t Ho = out_g_n_k_wos_lengths[3];
        const index_t Wo = out_g_n_k_wos_lengths[4];

        const index_t Y = wei_g_k_c_xs_lengths[3];
        const index_t X = wei_g_k_c_xs_lengths[4];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        // assume strided
        const auto in_n_c_hi_wi_c32_grid_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi, C_VECT),
                                         make_tuple(in_g_n_c_wis_strides[1],
                                                    in_g_n_c_wis_strides[2],
                                                    in_g_n_c_wis_strides[3],
                                                    in_g_n_c_wis_strides[4],
                                                    1));

        if constexpr(ConvBwdDataSpecialization ==
                     ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::
                         Filter1x1Stride1Pad0)
        {
            // C: input tensor
            const auto in_n_c_y_ho_x_wo_c32_grid_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(I1, Ho), make_tuple(I1, ConvStrideH)),
                           make_embed_transform(make_tuple(I1, Wo), make_tuple(I1, ConvStrideW)),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2, 3>{},
                           Sequence<4, 5>{},
                           Sequence<6>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_c_y_ho_x_wo_c32_grid_desc,
                make_tuple(make_freeze_transform(I0),
                           make_freeze_transform(I0),
                           make_merge_transform(make_tuple(N, Ho, Wo)),
                           make_merge_transform(make_tuple(C, C_VECT))),
                make_tuple(Sequence<2>{}, Sequence<4>{}, Sequence<0, 3, 5>{}, Sequence<1, 6>{}),
                make_tuple(Sequence<>{}, Sequence<>{}, Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
        else
        {
            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            const auto HTilde =
                Ho + math::integer_divide_ceil(ConvDilationH * (Y - I1), ConvStrideH);
            const auto WTilde =
                Wo + math::integer_divide_ceil(ConvDilationW * (X - I1), ConvStrideW);

            // only work on HTilde and WTilde that contribute to non-padding area of input tensor
            const auto IHTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadH - ConvDilationH * (YTilde - I1)), ConvStrideH);
            const auto IWTildeSliceBegin = math::integer_divide_floor(
                math::max(I0, InLeftPadW - ConvDilationW * (XTilde - I1)), ConvStrideW);

            const auto IHTildeSliceEnd = math::min(
                HTilde, math::integer_divide_ceil(InLeftPadH + Hi - I1, ConvStrideH) + I1);
            const auto IWTildeSliceEnd = math::min(
                WTilde, math::integer_divide_ceil(InLeftPadW + Wi - I1, ConvStrideW) + I1);

            const auto HTildeSlice = IHTildeSliceEnd - IHTildeSliceBegin;
            const auto WTildeSlice = IWTildeSliceEnd - IWTildeSliceBegin;

            // C: input tensor
            const auto in_n_c_hip_wip_c32_grid_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_n_c_ytilde_htilde_xtilde_wtilde_c32_grid_desc =
                transform_tensor_descriptor(
                    in_n_c_hip_wip_c32_grid_desc,
                    make_tuple(make_pass_through_transform(N),
                               make_pass_through_transform(C),
                               make_embed_transform(make_tuple(YTilde, HTilde),
                                                    make_tuple(ConvDilationH, ConvStrideH)),
                               make_embed_transform(make_tuple(XTilde, WTilde),
                                                    make_tuple(ConvDilationW, ConvStrideW)),
                               make_pass_through_transform(C_VECT)),
                    make_tuple(
                        Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                    make_tuple(Sequence<0>{},
                               Sequence<1>{},
                               Sequence<2, 3>{},
                               Sequence<4, 5>{},
                               Sequence<6>{}));

            const auto in_n_c_htildeslice_wtildeslice_c32_grid_desc = transform_tensor_descriptor(
                in_n_c_ytilde_htilde_xtilde_wtilde_c32_grid_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_freeze_transform(i_ytilde),
                           make_slice_transform(HTilde, IHTildeSliceBegin, HTildeSlice),
                           make_freeze_transform(i_xtilde),
                           make_slice_transform(WTilde, IWTildeSliceBegin, WTildeSlice),
                           make_pass_through_transform(C_VECT)),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<>{},
                           Sequence<2>{},
                           Sequence<>{},
                           Sequence<3>{},
                           Sequence<4>{}));

            const auto in_gemmmraw_gemmnraw_grid_desc = transform_tensor_descriptor(
                in_n_c_htildeslice_wtildeslice_c32_grid_desc,
                make_tuple(make_merge_transform(make_tuple(N, HTildeSlice, WTildeSlice)),
                           make_merge_transform(make_tuple(C, C_VECT))),
                make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmmraw_gemmnraw_grid_desc;
        }
    }
};

} // namespace tensor_operation
} // namespace ck
