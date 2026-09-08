// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Info Technologies Ltd.

#pragma once

#include "ck/library/utility/numeric.hpp"
#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_weight_specialization.hpp"

namespace ck {
namespace tensor_operation {

template <index_t NDimSpatial,
          device::ConvolutionBackwardWeightSpecialization ConvBwdWeightSpecialization>
struct TransformConvBwdWeightToGemm
{
    // output as GemmA
    template <typename ALayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<ALayout, tensor_layout::convolution::NHWGK> ||
                                           is_same_v<ALayout, tensor_layout::convolution::GNHWK>),
                                      bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_lenghts */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t N  = a_g_n_k_wos_lengths[1];
        const index_t Ho = a_g_n_k_wos_lengths[3];
        const index_t Wo = a_g_n_k_wos_lengths[4];
        const index_t K  = a_g_n_k_wos_lengths[2];

        const auto out_n_ho_wo_k_desc =
            make_naive_tensor_descriptor(make_tuple(N, Ho, Wo, K),
                                         make_tuple(a_g_n_k_wos_strides[1],
                                                    a_g_n_k_wos_strides[3],
                                                    a_g_n_k_wos_strides[4],
                                                    a_g_n_k_wos_strides[2]));

        const auto out_gemmm_gemmk_desc = transform_tensor_descriptor(
            out_n_ho_wo_k_desc,
            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)), make_pass_through_transform(K)),
            make_tuple(Sequence<0, 1, 2>{}, Sequence<3>{}),
            make_tuple(Sequence<1>{}, Sequence<0>{}));

        return out_gemmm_gemmk_desc;
    }

    template <typename ALayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<ALayout, tensor_layout::convolution::NGKHW> ||
                                           is_same_v<ALayout, tensor_layout::convolution::GNKHW>),
                                      bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_lenghts */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t N  = a_g_n_k_wos_lengths[1];
        const index_t K  = a_g_n_k_wos_lengths[2];
        const index_t Ho = a_g_n_k_wos_lengths[3];
        const index_t Wo = a_g_n_k_wos_lengths[4];

        const auto out_n_k_ho_wo_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo),
                                         make_tuple(a_g_n_k_wos_strides[1],
                                                    a_g_n_k_wos_strides[2],
                                                    a_g_n_k_wos_strides[3],
                                                    a_g_n_k_wos_strides[4]));

        const auto out_gemmm_gemmk_desc = transform_tensor_descriptor(
            out_n_k_ho_wo_desc,
            make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)), make_pass_through_transform(K)),
            make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
            make_tuple(Sequence<1>{}, Sequence<0>{}));

        return out_gemmm_gemmk_desc;
    }

#if 0
    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 && (is_same_v<ALayout, tensor_layout::convolution::NGKHWk32>),
                  bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_lenghts */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t K_VECT = 32;
        const index_t N      = a_g_n_k_wos_lengths[1];
        const index_t K      = a_g_n_k_wos_lengths[2];
        const index_t Ho     = a_g_n_k_wos_lengths[3];
        const index_t Wo     = a_g_n_k_wos_lengths[4];

        const auto out_n_k_ho_wo_k32_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo, K_VECT),
                                         make_tuple(a_g_n_k_wos_strides[1],
                                                    a_g_n_k_wos_strides[2],
                                                    a_g_n_k_wos_strides[3],
                                                    a_g_n_k_wos_strides[4],
                                                    1));

        const auto out_gemmm_gemmk_desc =
            transform_tensor_descriptor(out_n_k_ho_wo_k32_desc,
                                        make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                   make_merge_transform(make_tuple(K, K_VECT))),
                                        make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}),
                                        make_tuple(Sequence<1>{}, Sequence<0>{}));

        return out_gemmm_gemmk_desc;
    }
#endif

    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 2 &&
                      (std::is_base_of_v<ck::tensor_layout::convolution::NGCHWcBase, ALayout>),
                  bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_lenghts */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t K_VECT = ALayout::x;
        const index_t N      = a_g_n_k_wos_lengths[1];
        const index_t K      = a_g_n_k_wos_lengths[2];
        const index_t Ho     = a_g_n_k_wos_lengths[3];
        const index_t Wo     = a_g_n_k_wos_lengths[4];

        const auto out_n_k_ho_wo_k32_desc =
            make_naive_tensor_descriptor(make_tuple(N, K, Ho, Wo, K_VECT),
                                         make_tuple(a_g_n_k_wos_strides[1],
                                                    a_g_n_k_wos_strides[2],
                                                    a_g_n_k_wos_strides[3],
                                                    a_g_n_k_wos_strides[4],
                                                    1));

        const auto out_gemmm_gemmk_desc =
            transform_tensor_descriptor(out_n_k_ho_wo_k32_desc,
                                        make_tuple(make_merge_transform(make_tuple(N, Ho, Wo)),
                                                   make_merge_transform(make_tuple(K, K_VECT))),
                                        make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}),
                                        make_tuple(Sequence<1>{}, Sequence<0>{}));

        return out_gemmm_gemmk_desc;
    }

    // output as GemmA
    template <typename ALayout,
              typename std::enable_if<NDimSpatial == 3 &&
                                          is_same_v<ALayout, tensor_layout::convolution::NDHWGK>,
                                      bool>::type = false>
    static auto
    MakeADescriptor_M_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_lenghts */,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t N  = a_g_n_k_wos_lengths[1];
        const index_t Do = a_g_n_k_wos_lengths[3];
        const index_t Ho = a_g_n_k_wos_lengths[4];
        const index_t Wo = a_g_n_k_wos_lengths[5];
        const index_t K  = a_g_n_k_wos_lengths[2];

        const auto out_n_do_ho_wo_k_desc =
            make_naive_tensor_descriptor(make_tuple(N, Do, Ho, Wo, K),
                                         make_tuple(a_g_n_k_wos_strides[1],
                                                    a_g_n_k_wos_strides[3],
                                                    a_g_n_k_wos_strides[4],
                                                    a_g_n_k_wos_strides[5],
                                                    a_g_n_k_wos_strides[2]));

        const auto out_gemmm_gemmk_desc =
            transform_tensor_descriptor(out_n_do_ho_wo_k_desc,
                                        make_tuple(make_merge_transform(make_tuple(N, Do, Ho, Wo)),
                                                   make_pass_through_transform(K)),
                                        make_tuple(Sequence<0, 1, 2, 3>{}, Sequence<4>{}),
                                        make_tuple(Sequence<1>{}, Sequence<0>{}));

        return out_gemmm_gemmk_desc;
    }

    // input as GemmB
    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<BLayout, tensor_layout::convolution::NHWGC> ||
                                           is_same_v<BLayout, tensor_layout::convolution::GNHWC>),
                                      bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lenghts,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t N  = b_g_n_c_wis_lengths[1];
        const index_t Hi = b_g_n_c_wis_lengths[3];
        const index_t Wi = b_g_n_c_wis_lengths[4];
        const index_t C  = b_g_n_c_wis_lengths[2];

        const index_t Ho = a_g_n_k_wos_lengths[3];
        const index_t Wo = a_g_n_k_wos_lengths[4];

        const index_t Y = c_g_k_c_xs_lenghts[3];
        const index_t X = c_g_k_c_xs_lenghts[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const auto in_n_hi_wi_c_desc =
            make_naive_tensor_descriptor(make_tuple(N, Hi, Wi, C),
                                         make_tuple(b_g_n_c_wis_strides[1],
                                                    b_g_n_c_wis_strides[3],
                                                    b_g_n_c_wis_strides[4],
                                                    b_g_n_c_wis_strides[2]));

        if constexpr(ConvBwdWeightSpecialization ==
                     device::ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
        {
            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_hi_wi_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_pass_through_transform(C)),
                                            make_tuple(Sequence<0, 1, 2>{}, Sequence<3>{}),
                                            make_tuple(Sequence<1>{}, Sequence<0>{}));
            return in_gemmn_gemmk_desc;
        }
        else if constexpr(ConvBwdWeightSpecialization ==
                          device::ConvolutionBackwardWeightSpecialization::Filter1x1Pad0)
        {
            const auto in_n_ho_wo_c_desc = transform_tensor_descriptor(
                in_n_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_ho_wo_c_desc,
                                            make_tuple(make_pass_through_transform(C),
                                                       make_merge_transform(make_tuple(N, Ho, Wo))),
                                            make_tuple(Sequence<3>{}, Sequence<0, 1, 2>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
        else
        {
            const auto in_n_hip_wip_c_desc = transform_tensor_descriptor(
                in_n_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto in_n_y_ho_x_wo_c_desc = transform_tensor_descriptor(
                in_n_hip_wip_c_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(C)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3, 4>{}, Sequence<5>{}));

            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_y_ho_x_wo_c_desc,
                                            make_tuple(make_merge_transform(make_tuple(Y, X, C)),
                                                       make_merge_transform(make_tuple(N, Ho, Wo))),
                                            make_tuple(Sequence<1, 3, 5>{}, Sequence<0, 2, 4>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
    }

    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          (is_same_v<BLayout, tensor_layout::convolution::NGCHW> ||
                                           is_same_v<BLayout, tensor_layout::convolution::GNCHW>),
                                      bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lenghts,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t N  = b_g_n_c_wis_lengths[1];
        const index_t C  = b_g_n_c_wis_lengths[2];
        const index_t Hi = b_g_n_c_wis_lengths[3];
        const index_t Wi = b_g_n_c_wis_lengths[4];

        const index_t Ho = a_g_n_k_wos_lengths[3];
        const index_t Wo = a_g_n_k_wos_lengths[4];

        const index_t Y = c_g_k_c_xs_lenghts[3];
        const index_t X = c_g_k_c_xs_lenghts[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const auto in_n_c_hi_wi_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi),
                                         make_tuple(b_g_n_c_wis_strides[1],
                                                    b_g_n_c_wis_strides[2],
                                                    b_g_n_c_wis_strides[3],
                                                    b_g_n_c_wis_strides[4]));

        if constexpr(ConvBwdWeightSpecialization ==
                     device::ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
        {
            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_hi_wi_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_pass_through_transform(C)),
                                            make_tuple(Sequence<0, 2, 3>{}, Sequence<1>{}),
                                            make_tuple(Sequence<1>{}, Sequence<0>{}));
            return in_gemmn_gemmk_desc;
        }
        else if constexpr(ConvBwdWeightSpecialization ==
                          device::ConvolutionBackwardWeightSpecialization::Filter1x1Pad0)
        {
            const auto in_n_c_ho_wo_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW))),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_ho_wo_desc,
                                            make_tuple(make_pass_through_transform(C),
                                                       make_merge_transform(make_tuple(N, Ho, Wo))),
                                            make_tuple(Sequence<1>{}, Sequence<0, 2, 3>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
        else
        {
            const auto in_n_c_hip_wip_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW)),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}));

            const auto in_n_c_y_ho_x_wo_desc = transform_tensor_descriptor(
                in_n_c_hip_wip_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(C),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo),
                                         make_tuple(ConvDilationW, ConvStrideW))),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2, 3>{}, Sequence<4, 5>{}));

            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_y_ho_x_wo_desc,
                                            make_tuple(make_merge_transform(make_tuple(C, Y, X)),
                                                       make_merge_transform(make_tuple(N, Ho, Wo))),
                                            make_tuple(Sequence<1, 2, 4>{}, Sequence<0, 3, 5>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
    }

#if 0
    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 2 && (is_same_v<BLayout, tensor_layout::convolution::NGCHWc32>),
                  bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lenghts,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t C_VECT = 32;
        const index_t N      = b_g_n_c_wis_lengths[1];
        const index_t C      = b_g_n_c_wis_lengths[2];
        const index_t Hi     = b_g_n_c_wis_lengths[3];
        const index_t Wi     = b_g_n_c_wis_lengths[4];

        const index_t Ho = a_g_n_k_wos_lengths[3];
        const index_t Wo = a_g_n_k_wos_lengths[4];

        const index_t Y = c_g_k_c_xs_lenghts[3];
        const index_t X = c_g_k_c_xs_lenghts[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const auto in_n_c_hi_wi_c32_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi, C_VECT),
                                         make_tuple(b_g_n_c_wis_strides[1],
                                                    b_g_n_c_wis_strides[2],
                                                    b_g_n_c_wis_strides[3],
                                                    b_g_n_c_wis_strides[4],
                                                    1));

        if constexpr(ConvBwdWeightSpecialization ==
                     device::ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
        {
            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_hi_wi_c32_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_merge_transform(make_tuple(C, C_VECT))),
                                            make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}),
                                            make_tuple(Sequence<1>{}, Sequence<0>{}));
            return in_gemmn_gemmk_desc;
        }
        else if constexpr(ConvBwdWeightSpecialization ==
                          device::ConvolutionBackwardWeightSpecialization::Filter1x1Pad0)
        {
            const auto in_n_c_ho_wo_c32_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_ho_wo_c32_desc,
                                            make_tuple(make_merge_transform(make_tuple(C, C_VECT)),
                                                       make_merge_transform(make_tuple(N, Ho, Wo))),
                                            make_tuple(Sequence<1, 4>{}, Sequence<0, 2, 3>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
        else
        {
            const auto in_n_c_hip_wip_c32_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_n_c_y_ho_x_wo_c32_desc = transform_tensor_descriptor(
                in_n_c_hip_wip_c32_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(C),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2, 3>{},
                           Sequence<4, 5>{},
                           Sequence<6>{}));

            const auto in_gemmn_gemmk_desc = transform_tensor_descriptor(
                in_n_c_y_ho_x_wo_c32_desc,
                make_tuple(make_merge_transform(make_tuple(C, Y, X, C_VECT)),
                           make_merge_transform(make_tuple(N, Ho, Wo))),
                make_tuple(Sequence<1, 2, 4, 6>{}, Sequence<0, 3, 5>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
    }
#endif

    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 2 &&
                      (std::is_base_of_v<ck::tensor_layout::convolution::NGCHWcBase, BLayout>),
                  bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lenghts,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t C_VECT = BLayout::x;
        const index_t N      = b_g_n_c_wis_lengths[1];
        const index_t C      = b_g_n_c_wis_lengths[2];
        const index_t Hi     = b_g_n_c_wis_lengths[3];
        const index_t Wi     = b_g_n_c_wis_lengths[4];

        const index_t Ho = a_g_n_k_wos_lengths[3];
        const index_t Wo = a_g_n_k_wos_lengths[4];

        const index_t Y = c_g_k_c_xs_lenghts[3];
        const index_t X = c_g_k_c_xs_lenghts[4];

        const index_t ConvStrideH = conv_filter_strides[0];
        const index_t ConvStrideW = conv_filter_strides[1];

        const index_t ConvDilationH = conv_filter_dilations[0];
        const index_t ConvDilationW = conv_filter_dilations[1];

        const index_t InLeftPadH = input_left_pads[0];
        const index_t InLeftPadW = input_left_pads[1];

        const index_t InRightPadH = input_right_pads[0];
        const index_t InRightPadW = input_right_pads[1];

        const auto in_n_c_hi_wi_c32_desc =
            make_naive_tensor_descriptor(make_tuple(N, C, Hi, Wi, C_VECT),
                                         make_tuple(b_g_n_c_wis_strides[1],
                                                    b_g_n_c_wis_strides[2],
                                                    b_g_n_c_wis_strides[3],
                                                    b_g_n_c_wis_strides[4],
                                                    1));

        if constexpr(ConvBwdWeightSpecialization ==
                     device::ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
        {
            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_hi_wi_c32_desc,
                                            make_tuple(make_merge_transform(make_tuple(N, Hi, Wi)),
                                                       make_merge_transform(make_tuple(C, C_VECT))),
                                            make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}),
                                            make_tuple(Sequence<1>{}, Sequence<0>{}));
            return in_gemmn_gemmk_desc;
        }
        else if constexpr(ConvBwdWeightSpecialization ==
                          device::ConvolutionBackwardWeightSpecialization::Filter1x1Pad0)
        {
            const auto in_n_c_ho_wo_c32_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_gemmn_gemmk_desc =
                transform_tensor_descriptor(in_n_c_ho_wo_c32_desc,
                                            make_tuple(make_merge_transform(make_tuple(C, C_VECT)),
                                                       make_merge_transform(make_tuple(N, Ho, Wo))),
                                            make_tuple(Sequence<1, 4>{}, Sequence<0, 2, 3>{}),
                                            make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
        else
        {
            const auto in_n_c_hip_wip_c32_desc = transform_tensor_descriptor(
                in_n_c_hi_wi_c32_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pass_through_transform(C),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_n_c_y_ho_x_wo_c32_desc = transform_tensor_descriptor(
                in_n_c_hip_wip_c32_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_pass_through_transform(C),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(C_VECT)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2, 3>{},
                           Sequence<4, 5>{},
                           Sequence<6>{}));

            const auto in_gemmn_gemmk_desc = transform_tensor_descriptor(
                in_n_c_y_ho_x_wo_c32_desc,
                make_tuple(make_merge_transform(make_tuple(C, Y, X, C_VECT)),
                           make_merge_transform(make_tuple(N, Ho, Wo))),
                make_tuple(Sequence<1, 2, 4, 6>{}, Sequence<0, 3, 5>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
    }

    // input as GemmB
    template <typename BLayout,
              typename std::enable_if<NDimSpatial == 3 &&
                                          is_same_v<BLayout, tensor_layout::convolution::NDHWGC>,
                                      bool>::type = false>
    static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                        const std::array<index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lenghts,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<index_t, NDimSpatial>& input_left_pads,
                        const std::array<index_t, NDimSpatial>& input_right_pads)
    {
        const index_t N  = b_g_n_c_wis_lengths[1];
        const index_t Di = b_g_n_c_wis_lengths[3];
        const index_t Hi = b_g_n_c_wis_lengths[4];
        const index_t Wi = b_g_n_c_wis_lengths[5];
        const index_t C  = b_g_n_c_wis_lengths[2];

        const index_t Do = a_g_n_k_wos_lengths[3];
        const index_t Ho = a_g_n_k_wos_lengths[4];
        const index_t Wo = a_g_n_k_wos_lengths[5];

        const index_t Z = c_g_k_c_xs_lenghts[3];
        const index_t Y = c_g_k_c_xs_lenghts[4];
        const index_t X = c_g_k_c_xs_lenghts[5];

        const index_t ConvStrideD = conv_filter_strides[0];
        const index_t ConvStrideH = conv_filter_strides[1];
        const index_t ConvStrideW = conv_filter_strides[2];

        const index_t ConvDilationD = conv_filter_dilations[0];
        const index_t ConvDilationH = conv_filter_dilations[1];
        const index_t ConvDilationW = conv_filter_dilations[2];

        const index_t InLeftPadD = input_left_pads[0];
        const index_t InLeftPadH = input_left_pads[1];
        const index_t InLeftPadW = input_left_pads[2];

        const index_t InRightPadD = input_right_pads[0];
        const index_t InRightPadH = input_right_pads[1];
        const index_t InRightPadW = input_right_pads[2];

        const auto in_n_di_hi_wi_c_desc =
            make_naive_tensor_descriptor(make_tuple(N, Di, Hi, Wi, C),
                                         make_tuple(b_g_n_c_wis_strides[1],
                                                    b_g_n_c_wis_strides[3],
                                                    b_g_n_c_wis_strides[4],
                                                    b_g_n_c_wis_strides[5],
                                                    b_g_n_c_wis_strides[2]));

        if constexpr(ConvBwdWeightSpecialization ==
                     device::ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
        {
            const auto in_gemmn_gemmk_desc = transform_tensor_descriptor(
                in_n_di_hi_wi_c_desc,
                make_tuple(make_merge_transform(make_tuple(N, Di, Hi, Wi)),
                           make_pass_through_transform(C)),
                make_tuple(Sequence<0, 1, 2, 3>{}, Sequence<4>{}),
                make_tuple(Sequence<1>{}, Sequence<0>{}));
            return in_gemmn_gemmk_desc;
        }
        else if constexpr(ConvBwdWeightSpecialization ==
                          device::ConvolutionBackwardWeightSpecialization::Filter1x1Pad0)
        {
            const auto in_n_do_ho_wo_c_desc = transform_tensor_descriptor(
                in_n_di_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_embed_transform(make_tuple(Do), make_tuple(ConvStrideD)),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(C)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_gemmn_gemmk_desc = transform_tensor_descriptor(
                in_n_do_ho_wo_c_desc,
                make_tuple(make_pass_through_transform(C),
                           make_merge_transform(make_tuple(N, Do, Ho, Wo))),
                make_tuple(Sequence<4>{}, Sequence<0, 1, 2, 3>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
        else
        {
            const auto in_n_dip_hip_wip_c_desc = transform_tensor_descriptor(
                in_n_di_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pad_transform(Di, InLeftPadD, InRightPadD),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}));

            const auto in_n_z_do_y_ho_x_wo_c_desc = transform_tensor_descriptor(
                in_n_dip_hip_wip_c_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_embed_transform(make_tuple(Z, Do), make_tuple(ConvDilationD, ConvStrideD)),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(C)),
                make_tuple(
                    Sequence<0>{}, Sequence<1>{}, Sequence<2>{}, Sequence<3>{}, Sequence<4>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1, 2>{},
                           Sequence<3, 4>{},
                           Sequence<5, 6>{},
                           Sequence<7>{}));

            const auto in_gemmn_gemmk_desc = transform_tensor_descriptor(
                in_n_z_do_y_ho_x_wo_c_desc,
                make_tuple(make_merge_transform(make_tuple(Z, Y, X, C)),
                           make_merge_transform(make_tuple(N, Do, Ho, Wo))),
                make_tuple(Sequence<1, 3, 5, 7>{}, Sequence<0, 2, 4, 6>{}),
                make_tuple(Sequence<0>{}, Sequence<1>{}));

            return in_gemmn_gemmk_desc;
        }
    }

    // weight as GemmC
    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          is_same_v<CLayout, tensor_layout::convolution::GKYXC>,
                                      bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t K = c_g_k_c_xs_lengths[1];
        const index_t Y = c_g_k_c_xs_lengths[3];
        const index_t X = c_g_k_c_xs_lengths[4];
        const index_t C = c_g_k_c_xs_lengths[2];

        const auto wei_k_y_x_c_desc = make_naive_tensor_descriptor_packed(make_tuple(K, Y, X, C));

        const auto wei_gemmm_gemmn_desc = transform_tensor_descriptor(
            wei_k_y_x_c_desc,
            make_tuple(make_pass_through_transform(K), make_merge_transform(make_tuple(Y, X, C))),
            make_tuple(Sequence<0>{}, Sequence<1, 2, 3>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}));

        return wei_gemmm_gemmn_desc;
    }

    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          is_same_v<CLayout, tensor_layout::convolution::GKCYX>,
                                      bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t K = c_g_k_c_xs_lengths[1];
        const index_t C = c_g_k_c_xs_lengths[2];
        const index_t Y = c_g_k_c_xs_lengths[3];
        const index_t X = c_g_k_c_xs_lengths[4];

        const auto wei_k_c_y_x_desc = make_naive_tensor_descriptor_packed(make_tuple(K, C, Y, X));

        const auto wei_gemmm_gemmn_desc = transform_tensor_descriptor(
            wei_k_c_y_x_desc,
            make_tuple(make_pass_through_transform(K), make_merge_transform(make_tuple(C, Y, X))),
            make_tuple(Sequence<0>{}, Sequence<1, 2, 3>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}));

        return wei_gemmm_gemmn_desc;
    }

#if 0
    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 2 &&
                                          is_same_v<CLayout, tensor_layout::convolution::GKCYXc32>,
                                      bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t C_VECT = 32;
        const index_t K      = c_g_k_c_xs_lengths[1];
        const index_t C      = c_g_k_c_xs_lengths[2];
        const index_t Y      = c_g_k_c_xs_lengths[3];
        const index_t X      = c_g_k_c_xs_lengths[4];

        const auto wei_k_c_y_x_c32_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, C, Y, X, C_VECT));

        const auto wei_gemmm_gemmn_desc = transform_tensor_descriptor(
            wei_k_c_y_x_c32_desc,
            make_tuple(make_pass_through_transform(K),
                       make_merge_transform(make_tuple(C, Y, X, C_VECT))),
            make_tuple(Sequence<0>{}, Sequence<1, 2, 3, 4>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}));

        return wei_gemmm_gemmn_desc;
    }
#endif

    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 2 &&
                      std::is_base_of_v<ck::tensor_layout::convolution::GKCYXcBase, CLayout>,
                  bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t C_VECT = CLayout::x;
        const index_t K      = c_g_k_c_xs_lengths[1];
        const index_t C      = c_g_k_c_xs_lengths[2];
        const index_t Y      = c_g_k_c_xs_lengths[3];
        const index_t X      = c_g_k_c_xs_lengths[4];

        const auto wei_k_c_y_x_c32_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, C, Y, X, C_VECT));

        const auto wei_gemmm_gemmn_desc = transform_tensor_descriptor(
            wei_k_c_y_x_c32_desc,
            make_tuple(make_pass_through_transform(K),
                       make_merge_transform(make_tuple(C, Y, X, C_VECT))),
            make_tuple(Sequence<0>{}, Sequence<1, 2, 3, 4>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}));

        return wei_gemmm_gemmn_desc;
    }

    template <typename CLayout,
              typename std::enable_if<NDimSpatial == 3 &&
                                          is_same_v<CLayout, tensor_layout::convolution::GKZYXC>,
                                      bool>::type = false>
    static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* a_g_n_k_wos_strides */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_lengths */,
                        const std::array<index_t, NDimSpatial + 3>& /* b_g_n_c_wis_strides */,
                        const std::array<index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                        const std::array<index_t, NDimSpatial + 3>& /* c_g_k_c_xs_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_strides */,
                        const std::array<index_t, NDimSpatial>& /* conv_filter_dilations */,
                        const std::array<index_t, NDimSpatial>& /* input_left_pads */,
                        const std::array<index_t, NDimSpatial>& /* input_right_pads */)
    {
        const index_t K = c_g_k_c_xs_lengths[1];
        const index_t Z = c_g_k_c_xs_lengths[3];
        const index_t Y = c_g_k_c_xs_lengths[4];
        const index_t X = c_g_k_c_xs_lengths[5];
        const index_t C = c_g_k_c_xs_lengths[2];

        const auto wei_k_z_y_x_c_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, Z, Y, X, C));

        const auto wei_gemmm_gemmn_desc =
            transform_tensor_descriptor(wei_k_z_y_x_c_desc,
                                        make_tuple(make_pass_through_transform(K),
                                                   make_merge_transform(make_tuple(Z, Y, X, C))),
                                        make_tuple(Sequence<0>{}, Sequence<1, 2, 3, 4>{}),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}));

        return wei_gemmm_gemmn_desc;
    }
};

} // namespace tensor_operation
} // namespace ck
