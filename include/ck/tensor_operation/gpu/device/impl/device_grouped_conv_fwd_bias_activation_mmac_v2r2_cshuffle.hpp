// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <iostream>
#include <sstream>
#include <type_traits>

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/device_grouped_conv_fwd_bias_activation.hpp"
#include "ck/tensor_operation/gpu/device/convolution_forward_specialization.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_tn_mk_nk_mn_v2r2_cdop_cshuffle.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"
#include "ck/tensor_operation/operator_transform/transform_conv_fwd_to_gemm.hpp"
#include "ck/host_utility/device_prop.hpp"
#include "ck/host_utility/io.hpp"
#include "ck/host_utility/kernel_launch.hpp"

namespace ck {
namespace tensor_operation {
namespace device {

struct ComputePtrOffsetOfStridedBatch
{
    ComputePtrOffsetOfStridedBatch() = default;

    ComputePtrOffsetOfStridedBatch(ck::index_t BatchStrideA,
                                   ck::index_t BatchStrideB,
                                   ck::index_t BatchStrideC,
                                   ck::index_t BatchStrideC0)
        : BatchStrideA_(BatchStrideA),
          BatchStrideB_(BatchStrideB),
          BatchStrideC_(BatchStrideC),
          BatchStrideC0_(BatchStrideC0)
    {
    }

    __host__ __device__ constexpr long_index_t GetAPtrOffset(ck::index_t g_idx) const
    {
        return g_idx * static_cast<long_index_t>(BatchStrideA_);
    }

    __host__ __device__ constexpr long_index_t GetBPtrOffset(ck::index_t g_idx) const
    {
        return g_idx * static_cast<long_index_t>(BatchStrideB_);
    }

    __host__ __device__ constexpr long_index_t GetCPtrOffset(ck::index_t g_idx) const
    {
        return g_idx * static_cast<long_index_t>(BatchStrideC_);
    }

    __host__ __device__ constexpr long_index_t GetC0PtrOffset(ck::index_t g_idx) const
    {
        return g_idx * static_cast<long_index_t>(BatchStrideC0_);
    }

    ck::index_t BatchStrideA_;
    ck::index_t BatchStrideB_;
    ck::index_t BatchStrideC_;
    ck::index_t BatchStrideC0_;
};

template <typename GridwiseGemm,
          typename ADataType,
          typename BDataType,
          typename CDataType,
          typename C0DataType,
          typename AGridDesc_B_M_K,
          typename BGridDesc_B_N_K,
          typename CShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2,
          typename C0ShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename Block2CTileMap,
          typename ComputePtrOffsetOfBatch,
          bool HasMainK0BlockLoop,
          ck::index_t MaxThreadPerBlock = CK_MAX_THREAD_PER_BLOCK,
          ck::index_t MinBlockPerCU     = CK_MIN_BLOCK_PER_CU>
__global__ void __launch_bounds__(MaxThreadPerBlock, MinBlockPerCU) kernel_grouped_conv_fwd_mmac_v2(
    const ADataType* __restrict__ p_a_grid,
    const BDataType* __restrict__ p_b_grid,
    CDataType* __restrict__ p_c_grid,
    const C0DataType* __restrict__ p_c0_grid,
    const AGridDesc_B_M_K a_grid_desc_m_k,
    const BGridDesc_B_N_K b_grid_desc_n_k,
    const CShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2 cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2,
    const C0ShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2 c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2,
    const AElementwiseOperation a_element_op,
    const BElementwiseOperation b_element_op,
    const CElementwiseOperation c_element_op,
    const ck::index_t group_count,
    const Block2CTileMap block_2_ctile_map,
    const ComputePtrOffsetOfBatch compute_ptr_offset_of_batch,
    const index_t delta_h,
    const index_t delta_w,
    const index_t a_offset_delta_c,
    const index_t a_offset_delta_r,
    const index_t a_offset_delta_s,
    const index_t b_offset_delta_c,
    const index_t b_offset_delta_r,
    const index_t b_offset_delta_s,
    const index_t a_const_stride,
    const index_t b_const_stride)
{
#if (!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
     defined(__gfx936__) || defined(__gfx938__))
    __shared__ char p_shared[GridwiseGemm::GetSharedMemoryNumberOfByte()];

    // offset base pointer for each work-group
    const ck::index_t num_blocks_per_group =
        __builtin_amdgcn_readfirstlane(get_grid_size() / group_count);
    const ck::index_t g_idx =
        __builtin_amdgcn_readfirstlane(get_block_1d_id() / num_blocks_per_group);

    const long_index_t a_batch_offset = __builtin_amdgcn_readfirstlane(
        static_cast<long_index_t>(compute_ptr_offset_of_batch.GetAPtrOffset(g_idx)));
    const long_index_t b_batch_offset = __builtin_amdgcn_readfirstlane(
        static_cast<long_index_t>(compute_ptr_offset_of_batch.GetBPtrOffset(g_idx)));
    const long_index_t c_batch_offset = __builtin_amdgcn_readfirstlane(
        static_cast<long_index_t>(compute_ptr_offset_of_batch.GetCPtrOffset(g_idx)));
    const long_index_t c0_batch_offset = __builtin_amdgcn_readfirstlane(
        static_cast<long_index_t>(compute_ptr_offset_of_batch.GetC0PtrOffset(g_idx)));

    GridwiseGemm::template Run<HasMainK0BlockLoop>(p_a_grid + a_batch_offset,
                                                   p_b_grid + b_batch_offset,
                                                   p_c_grid + c_batch_offset,
                                                   p_c0_grid + c0_batch_offset,
                                                   p_shared,
                                                   a_grid_desc_m_k,
                                                   b_grid_desc_n_k,
                                                   cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2,
                                                   c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2,
                                                   a_element_op,
                                                   b_element_op,
                                                   c_element_op,
                                                   block_2_ctile_map,
                                                   delta_h,
                                                   delta_w,
                                                   a_offset_delta_c,
                                                   a_offset_delta_r,
                                                   a_offset_delta_s,
                                                   b_offset_delta_c,
                                                   b_offset_delta_r,
                                                   b_offset_delta_s,
                                                   a_const_stride,
                                                   b_const_stride);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = p_c0_grid;
    ignore = a_grid_desc_m_k;
    ignore = b_grid_desc_n_k;
    ignore = cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2;
    ignore = c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2;
    ignore = a_element_op;
    ignore = b_element_op;
    ignore = c_element_op;
    ignore = group_count;
    ignore = block_2_ctile_map;
    ignore = compute_ptr_offset_of_batch;
    ignore = delta_h;
    ignore = delta_w;
    ignore = a_offset_delta_c;
    ignore = a_offset_delta_r;
    ignore = a_offset_delta_s;
    ignore = b_offset_delta_c;
    ignore = b_offset_delta_r;
    ignore = b_offset_delta_s;
    ignore = a_const_stride;
    ignore = b_const_stride;
#endif // end of if (defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || defined(__gfx936__) ||
       // defined(__gfx938__))
}

template <ck::index_t NDimSpatial,
          typename ALayout,
          typename BLayout,
          typename CLayout,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename CDataType,
          typename C0DataType,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          ConvolutionForwardSpecialization ConvForwardSpecialization,
          ck::index_t WGSize,
          ck::index_t MPerWG,
          ck::index_t NPerBlock,
          ck::index_t KPerBlock,
          ck::index_t KPack_,
          ck::index_t MPerMmac,
          ck::index_t NPerMmac,
          ck::index_t MwaveRepeat,
          ck::index_t NwaveRepeat,
          ck::index_t MmmacRepeat,
          ck::index_t NmmacRepeat,
          ck::index_t MmmacInterleave,
          ck::index_t NmmacInterleave,
          typename ABlockTransferThreadClusterLengths_B_M_K,
          ck::index_t ABlockTransferSrcVectorDim,
          ck::index_t ABlockTransferSrcScalarPerVector,
          typename BBlockTransferThreadClusterLengths_B_N_K,
          ck::index_t BBlockTransferSrcVectorDim,
          ck::index_t BBlockTransferSrcScalarPerVector,
          index_t CShuffleMwaveRepeatPerShuffle,
          index_t CShuffleNwaveRepeatPerShuffle,
          typename CShuffleBlockTransferClusterLengths_M0_M1_M2_M3_N0_N1_N2,
          index_t CShuffleBlockTransferDstScalarPerVector,
          ck::index_t NumGemmKPrefetchStage,
          ck::index_t loop_remainder = 0>
struct DeviceGroupedConvFwdBiasActivation_mmac_v2r2_cshuffle
    : public DeviceGroupedConvFwdBiasActivation<NDimSpatial,
                                                ALayout,
                                                BLayout,
                                                CLayout,
                                                ADataType,
                                                BDataType,
                                                CDataType,
                                                C0DataType,
                                                AElementwiseOperation,
                                                BElementwiseOperation,
                                                CElementwiseOperation>
{
    using DeviceOp = DeviceGroupedConvFwdBiasActivation_mmac_v2r2_cshuffle;

    static_assert(
        is_same_v<AElementwiseOperation, ck::tensor_operation::element_wise::PassThrough>);
    static_assert(
        is_same_v<BElementwiseOperation, ck::tensor_operation::element_wise::PassThrough>);

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};

    static constexpr index_t NumWG     = 2;
    static constexpr index_t BlockSize = WGSize * NumWG;
    static constexpr index_t MPerBlock = MPerWG * NumWG;

    static constexpr auto conv_to_gemm_transformer =
        TransformConvFwdToGemm<NDimSpatial, ConvForwardSpecialization>{};

    static constexpr auto matrix_padder =
        MatrixPadder<GemmSpecialization::MNPadding, ck::index_t, ck::index_t, ck::index_t>{
            MPerBlock, NPerBlock, KPerBlock};

    static constexpr bool a_oob_check = true;
    static constexpr bool b_oob_check = true;

    static constexpr bool a_cache_swizzle = true;
    static constexpr bool b_cache_swizzle = true;

    static constexpr index_t ConvFilterR =
        ConvForwardSpecialization == ConvolutionForwardSpecialization::Filter7x7   ? 7
        : ConvForwardSpecialization == ConvolutionForwardSpecialization::Filter3x3 ? 3
                                                                                   : 1;
    static constexpr index_t ConvFilterS =
        ConvForwardSpecialization == ConvolutionForwardSpecialization::Filter7x7   ? 7
        : ConvForwardSpecialization == ConvolutionForwardSpecialization::Filter3x3 ? 3
                                                                                   : 1;

    static constexpr index_t KPack = math::gcd(Number<KPack_>{},
                                               Number<ABlockTransferSrcScalarPerVector>{},
                                               Number<BBlockTransferSrcScalarPerVector>{});

    static auto
    MakeAGridDescriptor_B_M_K(const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_strides,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                              const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_strides,
                              const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                              const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                              const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                              const std::array<ck::index_t, NDimSpatial>& input_right_pads)
    {
        const auto in_gemmmraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeADescriptor_M_K<ALayout, KPerBlock>(
                a_g_n_c_wis_lengths,
                a_g_n_c_wis_strides,
                b_g_k_c_xs_lengths,
                b_g_k_c_xs_strides,
                c_g_n_k_wos_lengths,
                c_g_n_k_wos_strides,
                conv_filter_strides,
                conv_filter_dilations,
                input_left_pads,
                input_right_pads);

        const auto in_gemmm_gemmk_desc =
            matrix_padder.PadADescriptor_M_K(in_gemmmraw_gemmkraw_desc);
        const auto gemm_m = in_gemmm_gemmk_desc.GetLength(I0);
        const auto gemm_k = in_gemmm_gemmk_desc.GetLength(I1);

        const auto in_b_gemmm_gemmk_desc =
            transform_tensor_descriptor(in_gemmm_gemmk_desc,
                                        make_tuple(make_pass_through_transform(gemm_m),
                                                   make_unmerge_transform(make_tuple(1, gemm_k))),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}),
                                        make_tuple(Sequence<1>{}, Sequence<0, 2>{}));

        return in_b_gemmm_gemmk_desc;
    }

    static auto
    MakeBGridDescriptor_B_N_K(const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides)
    {
        const auto wei_gemmnraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeBDescriptor_N_K<BLayout, KPerBlock>(
                b_g_k_c_xs_lengths, b_g_k_c_xs_strides);

        const auto wei_gemmn_gemmk_desc =
            matrix_padder.PadBDescriptor_N_K(wei_gemmnraw_gemmkraw_desc);
        const auto gemm_n = wei_gemmn_gemmk_desc.GetLength(I0);
        const auto gemm_k = wei_gemmn_gemmk_desc.GetLength(I1);

        const auto wei_b_gemmn_gemmk_desc =
            transform_tensor_descriptor(wei_gemmn_gemmk_desc,
                                        make_tuple(make_pass_through_transform(gemm_n),
                                                   make_unmerge_transform(make_tuple(1, gemm_k))),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}),
                                        make_tuple(Sequence<1>{}, Sequence<0, 2>{}));

        return wei_b_gemmn_gemmk_desc;
    }

    static auto
    MakeCGridDescriptor_M_N(const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_strides)
    {
        const auto out_gemmmraw_gemmnraw_desc =
            conv_to_gemm_transformer.template MakeCDescriptor_M_N<CLayout>(c_g_n_k_wos_lengths,
                                                                           c_g_n_k_wos_strides);

        const auto out_gemmm_gemmn_desc =
            matrix_padder.PadCDescriptor_M_N(out_gemmmraw_gemmnraw_desc);

        return out_gemmm_gemmn_desc;
    }

    static auto
    MakeC0GridDescriptor_M_N(const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_strides)
    {
        const auto out_gemmmraw_gemmnraw_desc =
            conv_to_gemm_transformer.template MakeCDescriptor_M_N<CLayout>(c_g_n_k_wos_lengths,
                                                                           c_g_n_k_wos_strides);

        const auto bias_gemmmraw_gemmnraw_desc =
            make_naive_tensor_descriptor(make_tuple(out_gemmmraw_gemmnraw_desc.GetLength(I0),
                                                    out_gemmmraw_gemmnraw_desc.GetLength(I1)),
                                         make_tuple(I0, I1));

        const auto bias_gemmm_gemmn_desc =
            matrix_padder.PadCDescriptor_M_N(bias_gemmmraw_gemmnraw_desc);

        return bias_gemmm_gemmn_desc;
    }

    // desc for problem definition
    using AGridDesc_B_M_K =
        remove_cvref_t<decltype(MakeAGridDescriptor_B_M_K({}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    using BGridDesc_B_N_K = remove_cvref_t<decltype(MakeBGridDescriptor_B_N_K({}, {}))>;
    using CGridDesc_M_N   = remove_cvref_t<decltype(MakeCGridDescriptor_M_N({}, {}))>;
    using C0GridDesc_M_N  = remove_cvref_t<decltype(MakeC0GridDescriptor_M_N({}, {}))>;

    using GridwiseGemm = GridwiseGemm_mmac_tn_mk_nk_mn_v2r2_cdop_cshuffle<
        WGSize,
        ADataType,
        BDataType,
        AccDataType,
        CDataType,
        C0DataType,
        InMemoryDataOperationEnum::Set,
        AElementwiseOperation,
        BElementwiseOperation,
        CElementwiseOperation,
        AGridDesc_B_M_K,
        BGridDesc_B_N_K,
        CGridDesc_M_N,
        C0GridDesc_M_N,
        MPerWG,
        NPerBlock,
        KPerBlock,
        KPack,
        MPerMmac,
        NPerMmac,
        MwaveRepeat,
        NwaveRepeat,
        MmmacRepeat,
        NmmacRepeat,
        MmmacInterleave,
        NmmacInterleave,
        ABlockTransferThreadClusterLengths_B_M_K,
        ABlockTransferSrcVectorDim,
        ABlockTransferSrcScalarPerVector,
        BBlockTransferThreadClusterLengths_B_N_K,
        BBlockTransferSrcVectorDim,
        BBlockTransferSrcScalarPerVector,
        CShuffleMwaveRepeatPerShuffle,
        CShuffleNwaveRepeatPerShuffle,
        CShuffleBlockTransferClusterLengths_M0_M1_M2_M3_N0_N1_N2,
        CShuffleBlockTransferDstScalarPerVector,
        NumGemmKPrefetchStage,
        ConvFilterR,
        ConvFilterS,
        a_oob_check,
        b_oob_check,
        a_cache_swizzle,
        b_cache_swizzle,
        loop_remainder>;

    // Argument
    struct Argument : public BaseArgument
    {

        Argument(const void* p_a,
                 const void* p_b,
                 void* p_c,
                 const void* p_c0,
                 const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_k_wos_strides,
                 const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                 const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                 const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                 const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                 ck::index_t M01,
                 ck::index_t N01,
                 const AElementwiseOperation& a_element_op,
                 const BElementwiseOperation& b_element_op,
                 const CElementwiseOperation& c_element_op)
            : p_a_grid_(static_cast<const ADataType*>(p_a)),
              p_b_grid_(static_cast<const BDataType*>(p_b)),
              p_c_grid_(static_cast<CDataType*>(p_c)),
              p_c0_grid_(static_cast<const C0DataType*>(p_c0)),
              num_group_(a_g_n_c_wis_lengths[0]),
              a_grid_desc_b_m_k_(MakeAGridDescriptor_B_M_K(a_g_n_c_wis_lengths,
                                                           a_g_n_c_wis_strides,
                                                           b_g_k_c_xs_lengths,
                                                           b_g_k_c_xs_strides,
                                                           c_g_n_k_wos_lengths,
                                                           c_g_n_k_wos_strides,
                                                           conv_filter_strides,
                                                           conv_filter_dilations,
                                                           input_left_pads,
                                                           input_right_pads)),
              b_grid_desc_b_n_k_(MakeBGridDescriptor_B_N_K(b_g_k_c_xs_lengths, b_g_k_c_xs_strides)),
              c_grid_desc_m_n_(MakeCGridDescriptor_M_N(c_g_n_k_wos_lengths, c_g_n_k_wos_strides)),
              c0_grid_desc_m_n_(MakeC0GridDescriptor_M_N(c_g_n_k_wos_lengths, c_g_n_k_wos_strides)),
              cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_(),
              c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_(),
              block_2_ctile_map_(),
              compute_ptr_offset_of_batch_(),
              M01_(M01),
              N01_(N01),
              a_element_op_(a_element_op),
              b_element_op_(b_element_op),
              c_element_op_(c_element_op),
              a_g_n_c_wis_lengths_{a_g_n_c_wis_lengths},
              a_g_n_c_wis_strides_{a_g_n_c_wis_strides},
              b_g_k_c_xs_lengths_{b_g_k_c_xs_lengths},
              b_g_k_c_xs_strides_{b_g_k_c_xs_strides},
              c_g_n_k_wos_lengths_{c_g_n_k_wos_lengths},
              c_g_n_k_wos_strides_{c_g_n_k_wos_strides},
              conv_filter_strides_{conv_filter_strides},
              conv_filter_dilations_{conv_filter_dilations},
              input_left_pads_{input_left_pads},
              input_right_pads_{input_right_pads}
        {
            // A/B/C Batch Stride
            compute_ptr_offset_of_batch_.BatchStrideA_  = a_g_n_c_wis_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideB_  = b_g_k_c_xs_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideC_  = c_g_n_k_wos_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideC0_ = c_g_n_k_wos_lengths[2];

            // for fast offset calculation
            const index_t DilationH = conv_filter_dilations[0];
            const index_t DilationW = conv_filter_dilations[1];
            const index_t R         = b_g_k_c_xs_lengths[3];
            const index_t S         = b_g_k_c_xs_lengths[4];
            const index_t StrideR   = b_g_k_c_xs_strides[3];
            const index_t StrideS   = b_g_k_c_xs_strides[4];
            const index_t StrideH   = a_g_n_c_wis_strides[3];
            const index_t StrideW   = a_g_n_c_wis_strides[4];
            const index_t StrideC   = b_g_k_c_xs_strides[2];

            // delta_h, delta_w
            delta_h_ = DilationH;
            delta_w_ = DilationW;

            // A delta_s, delta_r, delta_c
            a_offset_delta_[0] = StrideW * DilationW;
            a_offset_delta_[1] = StrideH * DilationH - (S - 1) * StrideW * DilationW;
            a_offset_delta_[2] =
                StrideC * KPerBlock - (R - 1) * StrideH * DilationH - (S - 1) * StrideW * DilationW;

            // B delta_s, delta_r, delta_c
            b_offset_delta_[0] = StrideS;
            b_offset_delta_[1] = StrideR - (S - 1) * StrideS;
            b_offset_delta_[2] = StrideC * KPerBlock - (R - 1) * StrideR - (S - 1) * StrideS;

            // A const_stride for cache swizzle: conv_stride * C
            a_const_stride_ = conv_filter_strides[0] * a_g_n_c_wis_strides[4] * sizeof(ADataType);
            // B const_stride for cache swizzle: C
            b_const_stride_ = b_g_k_c_xs_strides[4] * sizeof(BDataType);

            block_2_ctile_map_ =
                GridwiseGemm::MakeDefaultBlock2CTileMap(c_grid_desc_m_n_, M01, N01, 1);

            if(GridwiseGemm::CheckValidity(a_grid_desc_b_m_k_,
                                           b_grid_desc_b_n_k_,
                                           c_grid_desc_m_n_,
                                           c0_grid_desc_m_n_,
                                           block_2_ctile_map_))
            {
                cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_ =
                    GridwiseGemm::MakeCShuffleGridDescriptor_M0_M1_M2_M3_N0_N1_N2(c_grid_desc_m_n_);

                c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_ =
                    GridwiseGemm::MakeCShuffleGridDescriptor_M0_M1_M2_M3_N0_N1_N2(
                        c0_grid_desc_m_n_);
            }
        }

        void Print() const
        {
            std::cout << "A[M, K]: " << a_grid_desc_b_m_k_ << std::endl;
            std::cout << "B[N, K]: " << b_grid_desc_b_n_k_ << std::endl;
            std::cout << "C[M, N]: " << c_grid_desc_m_n_ << std::endl;
            std::cout << "C: " << cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_ << std::endl;
        }

        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;
        const C0DataType* p_c0_grid_;

        ck::index_t num_group_;
        AGridDesc_B_M_K a_grid_desc_b_m_k_;
        BGridDesc_B_N_K b_grid_desc_b_n_k_;
        CGridDesc_M_N c_grid_desc_m_n_;
        C0GridDesc_M_N c0_grid_desc_m_n_;
        typename GridwiseGemm::CShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2
            cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_;
        typename GridwiseGemm::C0ShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2
            c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_;
        typename GridwiseGemm::DefaultBlock2CTileMap block_2_ctile_map_;
        ComputePtrOffsetOfStridedBatch compute_ptr_offset_of_batch_;
        ck::index_t M01_;
        ck::index_t N01_;

        // elementwise op
        AElementwiseOperation a_element_op_;
        BElementwiseOperation b_element_op_;
        CElementwiseOperation c_element_op_;

        // conv problem desc
        std::array<ck::index_t, NDimSpatial + 3> a_g_n_c_wis_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> a_g_n_c_wis_strides_;
        std::array<ck::index_t, NDimSpatial + 3> b_g_k_c_xs_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> b_g_k_c_xs_strides_;
        std::array<ck::index_t, NDimSpatial + 3> c_g_n_k_wos_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> c_g_n_k_wos_strides_;
        std::array<ck::index_t, NDimSpatial> conv_filter_strides_;
        std::array<ck::index_t, NDimSpatial> conv_filter_dilations_;
        std::array<ck::index_t, NDimSpatial> input_left_pads_;
        std::array<ck::index_t, NDimSpatial> input_right_pads_;

        // precomputed delta table
        index_t a_offset_delta_[3];
        index_t b_offset_delta_[3];

        index_t delta_h_;
        index_t delta_w_;

        index_t a_const_stride_;
        index_t b_const_stride_;
    };

    // Invoker
    struct Invoker : public BaseInvoker
    {
        using Argument = DeviceOp::Argument;

        float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {
            if(stream_config.log_level_ > 0)
            {
                arg.Print();
            }

            if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_b_m_k_,
                                            arg.b_grid_desc_b_n_k_,
                                            arg.c_grid_desc_m_n_,
                                            arg.c0_grid_desc_m_n_,
                                            arg.block_2_ctile_map_))
            {
                throw std::runtime_error(
                    "wrong! GridwiseGemm_mmac_tn_mk_nk_mn_v2r1_cshuffle has invalid setting");
            }

            const ck::index_t grid_size =
                arg.block_2_ctile_map_.CalculateGridSize(arg.c_grid_desc_m_n_) * arg.num_group_;

            // 16 waves per CU
            constexpr index_t WaveSize      = 64;
            constexpr index_t MinWavePerCu  = 8;
            constexpr index_t WavesPerBlock = BlockSize / WaveSize;
            constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

            auto launch_kernel = [&](auto has_main_k_block_loop_) {
                constexpr bool has_main_loop = has_main_k_block_loop_.value;

                const auto kernel = kernel_grouped_conv_fwd_mmac_v2<
                    GridwiseGemm,
                    ADataType,
                    BDataType,
                    CDataType,
                    C0DataType,
                    remove_reference_t<DeviceOp::AGridDesc_B_M_K>,
                    remove_reference_t<DeviceOp::BGridDesc_B_N_K>,
                    remove_reference_t<
                        typename GridwiseGemm::CShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2>,
                    remove_reference_t<
                        typename GridwiseGemm::C0ShuffleGridDesc_M0_M1_M2_M3_N0_N1_N2>,
                    AElementwiseOperation,
                    BElementwiseOperation,
                    CElementwiseOperation,
                    remove_reference_t<typename GridwiseGemm::DefaultBlock2CTileMap>,
                    ComputePtrOffsetOfStridedBatch,
                    has_main_loop,
                    BlockSize,
                    MinBlockPerCU>;

                return launch_and_time_kernel(stream_config,
                                              kernel,
                                              dim3(grid_size),
                                              dim3(BlockSize),
                                              0,
                                              arg.p_a_grid_,
                                              arg.p_b_grid_,
                                              arg.p_c_grid_,
                                              arg.p_c0_grid_,
                                              arg.a_grid_desc_b_m_k_,
                                              arg.b_grid_desc_b_n_k_,
                                              arg.cshuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_,
                                              arg.c0shuffle_grid_desc_m0_m1_m2_m3_n0_n1_n2_,
                                              arg.a_element_op_,
                                              arg.b_element_op_,
                                              arg.c_element_op_,
                                              arg.num_group_,
                                              arg.block_2_ctile_map_,
                                              arg.compute_ptr_offset_of_batch_,
                                              arg.delta_h_,
                                              arg.delta_w_,
                                              arg.a_offset_delta_[2],
                                              arg.a_offset_delta_[1],
                                              arg.a_offset_delta_[0],
                                              arg.b_offset_delta_[2],
                                              arg.b_offset_delta_[1],
                                              arg.b_offset_delta_[0],
                                              arg.a_const_stride_,
                                              arg.b_const_stride_);
            };

            return launch_kernel(integral_constant<bool, true>{});
        }

        float Run(const BaseArgument* p_arg,
                  const StreamConfig& stream_config = StreamConfig{}) override
        {
            return Run(*dynamic_cast<const Argument*>(p_arg), stream_config);
        }
    };

    static bool IsSupportedArgument(const Argument& arg)
    {
        namespace ctc = tensor_layout::convolution;

        // FIXME: disable 256x128 instances due to vgpr spill
        if constexpr(MPerWG * NPerBlock > 128 * 128)
        {
            return false;
        }

        // cache swizzle only support 64 * (2^n) as const_stride
        if constexpr(a_cache_swizzle || b_cache_swizzle)
        {
            if(!math::ispow2(arg.b_g_k_c_xs_lengths_[2]))
            {
                return false;
            }
        }

        // only support gemm with main loop due to current implementation
        const auto GemmK = arg.a_grid_desc_b_m_k_.GetLength(I2);

        if(!GridwiseGemm::CalculateHasMainKBlockLoop(GemmK))
        {
            return false;
        }

        // device check
        static const auto hcu_target_enum = ck::get_hcu_target_enum();

        if(hcu_target_enum < HCUTargetEnum::HCU_TARGET_GFX928)
        {
            return false;
        }

        // // TODO: support mnk padding in underlying implementations
        // if((arg.c_g_n_k_wos_lengths_[1] * arg.c_g_n_k_wos_lengths_[3] *
        //     arg.c_g_n_k_wos_lengths_[4] % MPerBlock) != 0)
        // {
        //     return false;
        // }
        // else if(arg.c_g_n_k_wos_lengths_[2] % NPerBlock != 0)
        // {
        //     return false;
        // }
        // else if(arg.b_g_k_c_xs_lengths_[2] % KPerBlock != 0)
        // {
        //     return false;
        // }

        // TODO: only 1x1 & 3x3 & 7x7 support
        if constexpr(ConvForwardSpecialization ==
                     ConvolutionForwardSpecialization::Filter1x1Stride1Pad0)
        {
            // check if it's 1x1, stride=1 conv
            for(ck::index_t i = 0; i < NDimSpatial; ++i)
            {
                const ck::index_t X          = arg.b_g_k_c_xs_lengths_[i + 3];
                const ck::index_t ConvStride = arg.conv_filter_strides_[i];
                const ck::index_t LeftPad    = arg.input_left_pads_[i];
                const ck::index_t RightPad   = arg.input_right_pads_[i];

                if(!(X == 1 && ConvStride == 1 && LeftPad == 0 && RightPad == 0))
                {
                    return false;
                }
            }
        }
        else if constexpr(ConvForwardSpecialization ==
                          ConvolutionForwardSpecialization::Filter1x1Pad0)
        {
            bool is_f1x1s1p0_conv = true;

            // check if it's 1x1 conv
            for(ck::index_t i = 0; i < NDimSpatial; ++i)
            {
                const ck::index_t X          = arg.b_g_k_c_xs_lengths_[i + 3];
                const ck::index_t LeftPad    = arg.input_left_pads_[i];
                const ck::index_t RightPad   = arg.input_right_pads_[i];
                const ck::index_t ConvStride = arg.conv_filter_strides_[i];

                if(!(X == 1 && LeftPad == 0 && RightPad == 0))
                {
                    return false;
                }

                if(ConvStride != 1)
                {
                    is_f1x1s1p0_conv = false;
                }
            }

            // let Filter1x1Stride1Pad0 instance handle this
            if(is_f1x1s1p0_conv)
            {
                return false;
            }
        }
        else if constexpr(ConvForwardSpecialization == ConvolutionForwardSpecialization::Filter3x3)
        {
            if(NDimSpatial == 2)
            {
                if(arg.b_g_k_c_xs_lengths_[3] != 3 && arg.b_g_k_c_xs_lengths_[4] != 3)
                {
                    return false;
                }
            }
            else
            {
                return false;
            }
        }
        else if constexpr(ConvForwardSpecialization == ConvolutionForwardSpecialization::Filter7x7)
        {
            if(NDimSpatial == 2)
            {
                if(arg.b_g_k_c_xs_lengths_[3] != 7 && arg.b_g_k_c_xs_lengths_[4] != 7)
                {
                    return false;
                }
            }
            else
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // GemmA (activation) access check
        if constexpr(is_same_v<ALayout, ctc::NHWGC>)
        {
            const ck::index_t C = arg.a_g_n_c_wis_lengths_[2];

            if(!(ABlockTransferSrcVectorDim == 2 && C % ABlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // GemmB (weight) access check
        if constexpr(is_same_v<BLayout, ctc::GKYXC>)
        {
            const ck::index_t C = arg.b_g_k_c_xs_lengths_[2];

            if(!(BBlockTransferSrcVectorDim == 2 && C % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // Gemm C (output)
        if constexpr(is_same_v<CLayout, ctc::NHWGK>)
        {
            const ck::index_t K = arg.c_g_n_k_wos_lengths_[2];

            if(!(K % CShuffleBlockTransferDstScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // Gridwise GEMM size
        return GridwiseGemm::CheckValidity(arg.a_grid_desc_b_m_k_,
                                           arg.b_grid_desc_b_n_k_,
                                           arg.c_grid_desc_m_n_,
                                           arg.c0_grid_desc_m_n_,
                                           arg.block_2_ctile_map_);
    }

    bool IsSupportedArgument(const BaseArgument* p_arg) override
    {
        return IsSupportedArgument(*dynamic_cast<const Argument*>(p_arg));
    }

    static auto MakeArgument(const void* p_a,
                             const void* p_b,
                             void* p_c,
                             const void* p_c0,
                             const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_wos_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_wos_strides,
                             const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                             const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                             const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                             const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                             const AElementwiseOperation& a_element_op,
                             const BElementwiseOperation& b_element_op,
                             const CElementwiseOperation& c_element_op)
    {
        return Argument(p_a,
                        p_b,
                        p_c,
                        p_c0,
                        a_g_n_c_wis_lengths,
                        a_g_n_c_wis_strides,
                        b_g_k_c_xs_lengths,
                        b_g_k_c_xs_strides,
                        c_g_k_wos_lengths,
                        c_g_k_wos_strides,
                        conv_filter_strides,
                        conv_filter_dilations,
                        input_left_pads,
                        input_right_pads,
                        1,
                        1,
                        a_element_op,
                        b_element_op,
                        c_element_op);
    }

    static auto MakeInvoker() { return Invoker{}; }

    std::unique_ptr<BaseArgument>
    MakeArgumentPointer(const void* p_a,
                        const void* p_b,
                        void* p_c,
                        const void* p_c0,
                        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_wos_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_wos_strides,
                        const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                        const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                        const AElementwiseOperation& a_element_op,
                        const BElementwiseOperation& b_element_op,
                        const CElementwiseOperation& c_element_op) override
    {
        return std::make_unique<Argument>(p_a,
                                          p_b,
                                          p_c,
                                          p_c0,
                                          a_g_n_c_wis_lengths,
                                          a_g_n_c_wis_strides,
                                          b_g_k_c_xs_lengths,
                                          b_g_k_c_xs_strides,
                                          c_g_k_wos_lengths,
                                          c_g_k_wos_strides,
                                          conv_filter_strides,
                                          conv_filter_dilations,
                                          input_left_pads,
                                          input_right_pads,
                                          1,
                                          1,
                                          a_element_op,
                                          b_element_op,
                                          c_element_op);
    }

    std::unique_ptr<BaseInvoker> MakeInvokerPointer() override
    {
        return std::make_unique<Invoker>(Invoker{});
    }

    std::string GetTypeString() const override
    {
        auto str = std::stringstream();

        // WARNING: miopen can't get complement type string with comma, never use it!!
        // clang-format off
        str << "DeviceGroupedConvFwdBiasActivation_mmac_v2r2_cshuffle"
            << "-"
            << BlockSize << "-"
            << MPerBlock << "-"
            << NPerBlock << "-"
            << KPerBlock << "-"
            << KPack << "-"
            << getConvForwardSpecializationString(ConvForwardSpecialization) << "-"
            << MPerMmac << "-"
            << NPerMmac << "-"
            << MwaveRepeat << "-"
            << NwaveRepeat << "-"
            << MmmacRepeat << "-"
            << NmmacRepeat << "-"
            << MmmacInterleave << "-"
            << NmmacInterleave << "-"
            << ABlockTransferSrcScalarPerVector << "-"
            << BBlockTransferSrcScalarPerVector << "-"
            << CShuffleBlockTransferDstScalarPerVector << "-"
            << NumGemmKPrefetchStage << "-"
            << loop_remainder;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
