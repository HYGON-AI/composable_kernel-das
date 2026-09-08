// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv3d/utility/conv3d_fwd_spec.hpp"
#include "ck_tile/ops/common.hpp"

namespace ck_tile {
template <index_t NDimSpatial,
          index_t AVectorLength,
          index_t BVectorLength,
          index_t CVectorLength,
          Conv3dFwdSpec Spec>
struct Conv3dFwdToGemmTransformer
{
    static_assert(NDimSpatial == 3);

    static constexpr index_t NDim = NDimSpatial + 3;

    template <typename ALayout,
              typename std::enable_if<
                  NDimSpatial == 3 && std::is_same_v<ALayout, tensor_layout::convolution::NDHWGC>,
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
        const index_t Di = a_g_n_c_wis_lengths[3];
        const index_t Hi = a_g_n_c_wis_lengths[4];
        const index_t Wi = a_g_n_c_wis_lengths[5];
        const index_t C  = a_g_n_c_wis_lengths[2];

        const index_t Do = c_g_n_k_wos_lengths[3];
        const index_t Ho = c_g_n_k_wos_lengths[4];
        const index_t Wo = c_g_n_k_wos_lengths[5];

        if constexpr(Spec == Conv3dFwdSpec::Filter1x1x1Stride1Pad0)
        {
            const auto in_n_di_hi_wi_c_desc =
                make_naive_tensor_descriptor(make_tuple(N, Di, Hi, Wi, C),
                                             make_tuple(a_g_n_c_wis_strides[1],
                                                        a_g_n_c_wis_strides[3],
                                                        a_g_n_c_wis_strides[4],
                                                        a_g_n_c_wis_strides[5],
                                                        number<1>{}),
                                             number<AVectorLength>{},
                                             number<1>{});

            const auto in_gemmm_gemmk_desc = transform_tensor_descriptor(
                in_n_di_hi_wi_c_desc,
                make_tuple(make_merge_transform(make_tuple(N, Di, Hi, Wi)),
                           make_pass_through_transform(C)),
                make_tuple(sequence<0, 1, 2, 3>{}, sequence<4>{}),
                make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else if constexpr(Spec == Conv3dFwdSpec::Filter1x1x1Pad0)
        {
            const index_t ConvStrideD = conv_filter_strides[0];
            const index_t ConvStrideH = conv_filter_strides[1];
            const index_t ConvStrideW = conv_filter_strides[2];

            const auto in_n_di_hi_wi_c_desc =
                make_naive_tensor_descriptor(make_tuple(N, Di, Hi, Wi, C),
                                             make_tuple(a_g_n_c_wis_strides[1],
                                                        a_g_n_c_wis_strides[3],
                                                        a_g_n_c_wis_strides[4],
                                                        a_g_n_c_wis_strides[5],
                                                        number<1>{}),
                                             number<AVectorLength>{},
                                             number<1>{});

            const auto in_n_do_ho_wo_c_desc = transform_tensor_descriptor(
                in_n_di_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideD)),
                           make_embed_transform(make_tuple(Ho), make_tuple(ConvStrideH)),
                           make_embed_transform(make_tuple(Wo), make_tuple(ConvStrideW)),
                           make_pass_through_transform(C)),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}));

            const auto in_gemmm_gemmk_desc = transform_tensor_descriptor(
                in_n_do_ho_wo_c_desc,
                make_tuple(make_merge_transform(make_tuple(N, Do, Ho, Wo)),
                           make_pass_through_transform(C)),
                make_tuple(sequence<0, 1, 2, 3>{}, sequence<4>{}),
                make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
        else
        {
            const index_t Z = b_g_k_c_xs_lengths[3];
            const index_t Y = b_g_k_c_xs_lengths[4];
            const index_t X = b_g_k_c_xs_lengths[5];

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
                                             make_tuple(a_g_n_c_wis_strides[1],
                                                        a_g_n_c_wis_strides[3],
                                                        a_g_n_c_wis_strides[4],
                                                        a_g_n_c_wis_strides[5],
                                                        number<1>{}),
                                             number<AVectorLength>{},
                                             number<1>{});

            const auto in_n_dip_hip_wip_c_desc = transform_tensor_descriptor(
                in_n_di_hi_wi_c_desc,
                make_tuple(make_pass_through_transform(N),
                           make_pad_transform(Hi, InLeftPadD, InRightPadD),
                           make_pad_transform(Hi, InLeftPadH, InRightPadH),
                           make_pad_transform(Wi, InLeftPadW, InRightPadW),
                           make_pass_through_transform(C)),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}));

            const auto in_n_z_do_y_ho_x_wo_c_desc = transform_tensor_descriptor(
                in_n_dip_hip_wip_c_desc,
                make_tuple(
                    make_pass_through_transform(N),
                    make_embed_transform(make_tuple(Z, Do), make_tuple(ConvDilationD, ConvStrideD)),
                    make_embed_transform(make_tuple(Y, Ho), make_tuple(ConvDilationH, ConvStrideH)),
                    make_embed_transform(make_tuple(X, Wo), make_tuple(ConvDilationW, ConvStrideW)),
                    make_pass_through_transform(C)),
                make_tuple(
                    sequence<0>{}, sequence<1>{}, sequence<2>{}, sequence<3>{}, sequence<4>{}),
                make_tuple(sequence<0>{},
                           sequence<1, 2>{},
                           sequence<3, 4>{},
                           sequence<5, 6>{},
                           sequence<7>{}));

            const auto in_gemmm_gemmk_desc = transform_tensor_descriptor(
                in_n_z_do_y_ho_x_wo_c_desc,
                make_tuple(make_merge_transform(make_tuple(N, Do, Ho, Wo)),
                           make_merge_transform(make_tuple(Z, Y, X, C))),
                make_tuple(sequence<0, 2, 4, 6>{}, sequence<1, 3, 5, 7>{}),
                make_tuple(sequence<0>{}, sequence<1>{}));

            return in_gemmm_gemmk_desc;
        }
    }

    template <typename BLayout,
              typename std::enable_if<
                  NDimSpatial == 3 && std::is_same_v<BLayout, tensor_layout::convolution::GKZYXC>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeBDescriptor_N_K(const std::array<index_t, NDim>& b_g_k_c_xs_lengths,
                        const std::array<index_t, NDim>& /* b_g_k_c_xs_strides */)
    {
        const index_t K = b_g_k_c_xs_lengths[1];
        const index_t Z = b_g_k_c_xs_lengths[3];
        const index_t Y = b_g_k_c_xs_lengths[4];
        const index_t X = b_g_k_c_xs_lengths[5];
        const index_t C = b_g_k_c_xs_lengths[2];

        const auto wei_k_z_y_x_c_desc =
            make_naive_tensor_descriptor_packed(make_tuple(K, Z, Y, X, C), number<BVectorLength>{});

        const auto wei_gemmn_gemmk_desc =
            transform_tensor_descriptor(wei_k_z_y_x_c_desc,
                                        make_tuple(make_pass_through_transform(K),
                                                   make_merge_transform(make_tuple(Z, Y, X, C))),
                                        make_tuple(sequence<0>{}, sequence<1, 2, 3, 4>{}),
                                        make_tuple(sequence<0>{}, sequence<1>{}));

        return wei_gemmn_gemmk_desc;
    }

    template <typename CLayout,
              typename std::enable_if<
                  NDimSpatial == 3 && std::is_same_v<CLayout, tensor_layout::convolution::NDHWGK>,
                  bool>::type = false>
    CK_TILE_HOST static auto
    MakeCDescriptor_M_N(const std::array<index_t, NDim>& c_g_n_k_wos_lengths,
                        const std::array<index_t, NDim>& c_g_n_k_wos_strides)
    {
        const index_t N  = c_g_n_k_wos_lengths[1];
        const index_t Do = c_g_n_k_wos_lengths[3];
        const index_t Ho = c_g_n_k_wos_lengths[4];
        const index_t Wo = c_g_n_k_wos_lengths[5];
        const index_t K  = c_g_n_k_wos_lengths[2];

        const index_t NDoHoWo = N * Do * Ho * Wo;

        const auto out_gemmm_gemmn_desc =
            make_naive_tensor_descriptor(make_tuple(NDoHoWo, K),
                                         make_tuple(c_g_n_k_wos_strides[5], number<1>{}),
                                         number<CVectorLength>{},
                                         number<1>{});

        return out_gemmm_gemmn_desc;
    }
};

} // namespace ck_tile
