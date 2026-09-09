// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <iostream>
#include <numeric>
#include <sstream>

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/device_grouped_conv_bwd_weight.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_weight_specialization.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_bwd_weight.hpp"
#include "ck/tensor_operation/operator_transform/transform_conv_bwd_weight_to_gemm.hpp"
#include "ck/host_utility/device_prop.hpp"
#include "ck/host_utility/kernel_launch.hpp"

namespace ck {
namespace tensor_operation {
namespace device {

namespace {

struct ComputePtrOffsetOfStridedBatch
{
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

    ck::index_t BatchStrideA_;
    ck::index_t BatchStrideB_;
    ck::index_t BatchStrideC_;
};

} // namespace

template <typename GridwiseGemm,
          typename ADataType,
          typename BDataType,
          typename CDataType,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename AGridDesc_B_K0_M_K1,
          typename BGridDesc_B_K0_N_K1,
          typename CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2,
          typename Block2CTileMap,
          typename ComputePtrOffsetOfBatch,
          bool HasMainKBlockLoop,
          ck::index_t MaxThreadPerBlock = CK_MAX_THREAD_PER_BLOCK,
          ck::index_t MinBlockPerCU     = CK_MIN_BLOCK_PER_CU>
__global__ void
#if CK_USE_LAUNCH_BOUNDS
__launch_bounds__(MaxThreadPerBlock, MinBlockPerCU)
#endif
    kernel_grouped_conv_bwd_weight_mmac(
        const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const AElementwiseOperation a_element_op,
        const BElementwiseOperation b_element_op,
        const CElementwiseOperation c_element_op,
        const ck::index_t group_count,
        const AGridDesc_B_K0_M_K1 a_b_k0_m_k1_grid_desc,
        const BGridDesc_B_K0_N_K1 b_b_k0_n_k1_grid_desc,
        const CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2 c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2,
        const Block2CTileMap block_2_ctile_map,
        const ComputePtrOffsetOfBatch compute_ptr_offset_of_batch)
{
#if (!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
     defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__))
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

    __shared__ char p_shared[GridwiseGemm::GetSharedMemoryNumberOfByte()];

    GridwiseGemm::template Run<HasMainKBlockLoop>(p_a_grid + a_batch_offset,
                                                  p_b_grid + b_batch_offset,
                                                  p_c_grid + c_batch_offset,
                                                  p_shared,
                                                  a_b_k0_m_k1_grid_desc,
                                                  b_b_k0_n_k1_grid_desc,
                                                  c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2,
                                                  a_element_op,
                                                  b_element_op,
                                                  c_element_op,
                                                  block_2_ctile_map);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = a_b_k0_m_k1_grid_desc;
    ignore = b_b_k0_n_k1_grid_desc;
    ignore = c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2;
    ignore = a_element_op;
    ignore = b_element_op;
    ignore = c_element_op;
    ignore = group_count;
    ignore = block_2_ctile_map;
    ignore = compute_ptr_offset_of_batch;

    compute_ptr_offset_of_batch.GetAPtrOffset(0);
    compute_ptr_offset_of_batch.GetBPtrOffset(0);
    compute_ptr_offset_of_batch.GetCPtrOffset(0);
#endif // end of if (defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || defined(__gfx936__) ||
       // defined(__gfx938__) || defined(__gfx946__))
}

template <ck::index_t NDimSpatial,
          typename ALayout,
          typename BLayout,
          typename CLayout,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename CDataType,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          ConvolutionBackwardWeightSpecialization ConvBackwardWeightSpecialization,
          ck::index_t BlockSize,
          ck::index_t MPerBlock,
          ck::index_t NPerBlock,
          ck::index_t K0PerBlock,
          ck::index_t K1,
          ck::index_t MPerMmac,
          ck::index_t NPerMmac,
          ck::index_t MMmacPerWave,
          ck::index_t NMmacPerWave,
          typename ABlockTransferThreadClusterLengths_B_K0_M_K1,
          typename ABlockTransferThreadClusterArrangeOrder,
          typename ABlockTransferSrcAccessOrder,
          ck::index_t ABlockTransferSrcVectorDim,
          ck::index_t ABlockTransferSrcScalarPerVector,
          ck::index_t ABlockTransferDstScalarPerVector_K1,
          bool ABlockLdsAddExtraM,
          typename BBlockTransferThreadClusterLengths_B_K0_N_K1,
          typename BBlockTransferThreadClusterArrangeOrder,
          typename BBlockTransferSrcAccessOrder,
          ck::index_t BBlockTransferSrcVectorDim,
          ck::index_t BBlockTransferSrcScalarPerVector,
          ck::index_t BBlockTransferDstScalarPerVector_K1,
          bool BBlockLdsAddExtraN,
          ck::index_t NumGemmKPrefetchStage = 1,
          ck::index_t GemmKSplitFactor      = 1,
          LoopScheduler LoopSched           = make_default_loop_scheduler()>
struct DeviceGroupedConvBwdWeight_Mmac : public DeviceGroupedConvBwdWeightV2<NDimSpatial,
                                                                             ALayout,
                                                                             BLayout,
                                                                             CLayout,
                                                                             ADataType,
                                                                             BDataType,
                                                                             CDataType,
                                                                             AElementwiseOperation,
                                                                             BElementwiseOperation,
                                                                             CElementwiseOperation>
{
    using DeviceOp = DeviceGroupedConvBwdWeight_Mmac;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};

    static constexpr auto conv_to_gemm_transformer =
        TransformConvBwdWeightToGemm<NDimSpatial, ConvBackwardWeightSpecialization>{};

    static constexpr auto matrix_padder =
        MatrixPadder<GemmSpecialization::MNPadding, ck::index_t, ck::index_t, ck::index_t>{
            MPerBlock, NPerBlock, K0PerBlock* K1};

    // Bytes per 32 lds bank: 32 * 4 bytes
    static constexpr auto BankLength = 128;
    static constexpr auto ElePerBank = BankLength / sizeof(ADataType);

    // M1 & M0
    static constexpr auto ABlockLdsM1PerBlock = ElePerBank / K1;
    static constexpr auto ABlockLdsM0PerBlock = MPerBlock / ABlockLdsM1PerBlock;
    static constexpr auto ABlockLdsM1Padding  = 4;

    // N1 & N0
    static constexpr auto BBlockLdsN1PerBlock = ElePerBank / K1;
    static constexpr auto BBlockLdsN0PerBlock = NPerBlock / BBlockLdsN1PerBlock;
    static constexpr auto BBlockLdsN1Padding  = 4;

    static auto MakeAGridDescriptor_KBatch_K0_M_K1(
        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
        const std::array<ck::index_t, NDimSpatial>& input_left_pads,
        const std::array<ck::index_t, NDimSpatial>& input_right_pads,
        const ck::index_t k0,
        const ck::index_t ksplit)
    {
        const auto out_gemmmraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeADescriptor_M_K<ALayout>(a_g_n_k_wos_lengths,
                                                                           a_g_n_k_wos_strides,
                                                                           b_g_n_c_wis_lengths,
                                                                           b_g_n_c_wis_strides,
                                                                           c_g_k_c_xs_lengths,
                                                                           c_g_k_c_xs_strides,
                                                                           conv_filter_strides,
                                                                           conv_filter_dilations,
                                                                           input_left_pads,
                                                                           input_right_pads);

        const auto out_gemmm_gemmkraw_desc =
            matrix_padder.PadADescriptor_M_K(out_gemmmraw_gemmkraw_desc);

        const ck::index_t gemm_m     = out_gemmm_gemmkraw_desc.GetLength(I0);
        const ck::index_t gemm_k_raw = out_gemmm_gemmkraw_desc.GetLength(I1);
        const ck::index_t gemm_k_pad = ksplit * k0 * K1;

        const auto out_gemmm_gemmk_desc = transform_tensor_descriptor(
            out_gemmm_gemmkraw_desc,
            make_tuple(make_pass_through_transform(gemm_m),
                       make_right_pad_transform(gemm_k_raw, gemm_k_pad - gemm_k_raw)),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}));

        const auto out_gemmkbatch_gemmk0_gemmm_gemmk1_desc = transform_tensor_descriptor(
            out_gemmm_gemmk_desc,
            make_tuple(make_pass_through_transform(gemm_m),
                       make_unmerge_transform(make_tuple(ksplit, k0, K1))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<2>{}, Sequence<0, 1, 3>{}));

        return out_gemmkbatch_gemmk0_gemmm_gemmk1_desc;
    }

    static auto MakeBGridDescriptor_KBatch_K0_N_K1(
        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
        const std::array<ck::index_t, NDimSpatial>& input_left_pads,
        const std::array<ck::index_t, NDimSpatial>& input_right_pads,
        const ck::index_t k0,
        const ck::index_t ksplit)
    {
        const auto in_gemmnraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeBDescriptor_N_K<BLayout>(a_g_n_k_wos_lengths,
                                                                           a_g_n_k_wos_strides,
                                                                           b_g_n_c_wis_lengths,
                                                                           b_g_n_c_wis_strides,
                                                                           c_g_k_c_xs_lengths,
                                                                           c_g_k_c_xs_strides,
                                                                           conv_filter_strides,
                                                                           conv_filter_dilations,
                                                                           input_left_pads,
                                                                           input_right_pads);

        const auto in_gemmn_gemmkraw_desc =
            matrix_padder.PadBDescriptor_N_K(in_gemmnraw_gemmkraw_desc);

        const ck::index_t gemm_n     = in_gemmn_gemmkraw_desc.GetLength(I0);
        const ck::index_t gemm_k_raw = in_gemmn_gemmkraw_desc.GetLength(I1);
        const ck::index_t gemm_k_pad = ksplit * k0 * K1;

        const auto in_gemmn_gemmk_desc = transform_tensor_descriptor(
            in_gemmn_gemmkraw_desc,
            make_tuple(make_pass_through_transform(gemm_n),
                       make_right_pad_transform(gemm_k_raw, gemm_k_pad - gemm_k_raw)),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}));

        const auto in_gemmkbatch_gemmk0_gemmn_gemmk1_desc = transform_tensor_descriptor(
            in_gemmn_gemmk_desc,
            make_tuple(make_pass_through_transform(gemm_n),
                       make_unmerge_transform(make_tuple(ksplit, k0, K1))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<2>{}, Sequence<0, 1, 3>{}));

        return in_gemmkbatch_gemmk0_gemmn_gemmk1_desc;
    }

    static auto
    MakeCGridDescriptor_M_N(const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                            const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                            const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
                            const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                            const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                            const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                            const std::array<ck::index_t, NDimSpatial>& input_right_pads)
    {
        const auto wei_gemmmraw_gemmnraw_desc =
            conv_to_gemm_transformer.template MakeCDescriptor_M_N<CLayout>(a_g_n_k_wos_lengths,
                                                                           a_g_n_k_wos_strides,
                                                                           b_g_n_c_wis_lengths,
                                                                           b_g_n_c_wis_strides,
                                                                           c_g_k_c_xs_lengths,
                                                                           c_g_k_c_xs_strides,
                                                                           conv_filter_strides,
                                                                           conv_filter_dilations,
                                                                           input_left_pads,
                                                                           input_right_pads);

        const auto wei_gemmm_gemmn_desc =
            matrix_padder.PadCDescriptor_M_N(wei_gemmmraw_gemmnraw_desc);

        return wei_gemmm_gemmn_desc;
    }

    using AGridDesc_B_K0_M_K1 = remove_cvref_t<decltype(MakeAGridDescriptor_KBatch_K0_M_K1(
        {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, 1, 1))>;
    using BGridDesc_B_K0_N_K1 = remove_cvref_t<decltype(MakeBGridDescriptor_KBatch_K0_N_K1(
        {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, 1, 1))>;
    using CGridDesc_M_N       = remove_cvref_t<decltype(MakeCGridDescriptor_M_N(
        {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}, {1}))>;

    using GridwiseGemm =
        GridwiseGemm_bk0mk1_bk0nk1_mn_mmac_bwd_weight<BlockSize,
                                                      ADataType,
                                                      BDataType,
                                                      AccDataType,
                                                      CDataType,
                                                      AGridDesc_B_K0_M_K1,
                                                      BGridDesc_B_K0_N_K1,
                                                      CGridDesc_M_N,
                                                      AElementwiseOperation,
                                                      BElementwiseOperation,
                                                      CElementwiseOperation,
                                                      MPerBlock,
                                                      NPerBlock,
                                                      K0PerBlock,
                                                      MPerMmac,
                                                      NPerMmac,
                                                      K1,
                                                      MMmacPerWave,
                                                      NMmacPerWave,
                                                      ABlockTransferThreadClusterLengths_B_K0_M_K1,
                                                      ABlockTransferThreadClusterArrangeOrder,
                                                      ABlockTransferSrcAccessOrder,
                                                      ABlockTransferSrcVectorDim,
                                                      ABlockTransferSrcScalarPerVector,
                                                      ABlockTransferDstScalarPerVector_K1,
                                                      false,
                                                      ABlockLdsAddExtraM,
                                                      ABlockLdsM1PerBlock,
                                                      ABlockLdsM0PerBlock,
                                                      ABlockLdsM1Padding,
                                                      BBlockTransferThreadClusterLengths_B_K0_N_K1,
                                                      BBlockTransferThreadClusterArrangeOrder,
                                                      BBlockTransferSrcAccessOrder,
                                                      BBlockTransferSrcVectorDim,
                                                      BBlockTransferSrcScalarPerVector,
                                                      BBlockTransferDstScalarPerVector_K1,
                                                      false,
                                                      BBlockLdsAddExtraN,
                                                      BBlockLdsN1PerBlock,
                                                      BBlockLdsN0PerBlock,
                                                      BBlockLdsN1Padding,
                                                      Sequence<2, 3, 0, 1, 4, 5, 6, 7>,
                                                      7,
                                                      1,
                                                      true,
                                                      true,
                                                      NumGemmKPrefetchStage,
                                                      LoopSched>;

    // Argument
    using CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2 =
        decltype(GridwiseGemm::MakeCGridDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(CGridDesc_M_N{}));

    using Block2CTileMap =
        decltype(GridwiseGemm::MakeCBlockClusterAdaptor(CGridDesc_M_N{}, 1, 1, 1));

    struct Argument : public BaseArgument
    {
        Argument(const void* p_a,
                 const void* p_b,
                 void* p_c,
                 const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
                 const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                 const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                 const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                 const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                 const AElementwiseOperation& a_element_op,
                 const BElementwiseOperation& b_element_op,
                 const CElementwiseOperation& c_element_op,
                 const ck::index_t M01,
                 const ck::index_t N01)
            : p_a_grid_(static_cast<const ADataType*>(p_a)),
              p_b_grid_(static_cast<const BDataType*>(p_b)),
              p_c_grid_(static_cast<CDataType*>(p_c)),
              num_group_(a_g_n_k_wos_lengths[0]),
              a_grid_desc_b_k0_m_k1_(),
              b_grid_desc_b_k0_n_k1_(),
              c_grid_desc_m_n_(),
              c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2_(),
              block_2_ctile_map_(),
              compute_ptr_offset_of_batch_(),
              M01_(M01),
              N01_(N01),
              a_element_op_(a_element_op),
              b_element_op_(b_element_op),
              c_element_op_(c_element_op),
              a_g_n_k_wos_lengths_(a_g_n_k_wos_lengths),
              a_g_n_k_wos_strides_(a_g_n_k_wos_strides),
              b_g_n_c_wis_lengths_(b_g_n_c_wis_lengths),
              b_g_n_c_wis_strides_(b_g_n_c_wis_strides),
              c_g_k_c_xs_lengths_(c_g_k_c_xs_lengths),
              c_g_k_c_xs_strides_(c_g_k_c_xs_strides),
              conv_filter_strides_(conv_filter_strides),
              conv_filter_dilations_(conv_filter_dilations),
              input_left_pads_(input_left_pads),
              input_right_pads_(input_right_pads)
        {
            // A/B/C Batch Stride
            compute_ptr_offset_of_batch_.BatchStrideA_ = a_g_n_k_wos_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideB_ = b_g_n_c_wis_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideC_ = c_g_k_c_xs_strides[0];

            // split k computation, from miopen
            c_grid_desc_m_n_  = MakeCGridDescriptor_M_N(a_g_n_k_wos_lengths,
                                                       a_g_n_k_wos_strides,
                                                       b_g_n_c_wis_lengths,
                                                       b_g_n_c_wis_strides,
                                                       c_g_k_c_xs_lengths,
                                                       c_g_k_c_xs_strides,
                                                       conv_filter_strides,
                                                       conv_filter_dilations,
                                                       input_left_pads,
                                                       input_right_pads);
            const auto gemm_m = c_grid_desc_m_n_.GetLength(I0);
            const auto gemm_n = c_grid_desc_m_n_.GetLength(I1);

            const ck::index_t max_grid_size = GemmKSplitFactor * ck_tile::get_num_cu();
            const ck::index_t grid_size_without_split_gemmk =
                num_group_ * (gemm_m / MPerBlock) * (gemm_n / NPerBlock);

            const ck::index_t n  = a_g_n_k_wos_lengths_[1];
            const ck::index_t ho = a_g_n_k_wos_lengths_[3];
            const ck::index_t wo = a_g_n_k_wos_lengths_[4];
            ck::index_t ksplit   = -1;
            ksplit               = math::max(max_grid_size / grid_size_without_split_gemmk, 1);
            // ksplit should not be greater than batchsize
            // to ensure correctness of vector load among gemm k dimension
            ksplit = math::min(ksplit, n);

            const ck::index_t KPerBlock = K0PerBlock * K1;
            for(; ksplit > 1; ksplit--)
            {
                if(n % ksplit != 0)
                    continue;

                const ck::index_t n_sub = n / ksplit;

                const ck::index_t gemm_k_total_raw = n_sub * ho * wo;

                const ck::index_t gemm_k_total =
                    ((gemm_k_total_raw - 1) / KPerBlock + 1) * KPerBlock;

                if(!(gemm_k_total % (KPerBlock) == 0))
                    continue;
                break;
            }

            const ck::index_t n_sub = n / ksplit;

            const ck::index_t gemm_k_total_raw = n_sub * ho * wo;

            const ck::index_t gemm_k_total = ((gemm_k_total_raw - 1) / KPerBlock + 1) * KPerBlock;

            const ck::index_t k0 = gemm_k_total / K1;

            // A desc
            a_grid_desc_b_k0_m_k1_ = MakeAGridDescriptor_KBatch_K0_M_K1(a_g_n_k_wos_lengths,
                                                                        a_g_n_k_wos_strides,
                                                                        b_g_n_c_wis_lengths,
                                                                        b_g_n_c_wis_strides,
                                                                        c_g_k_c_xs_lengths,
                                                                        c_g_k_c_xs_strides,
                                                                        conv_filter_strides,
                                                                        conv_filter_dilations,
                                                                        input_left_pads,
                                                                        input_right_pads,
                                                                        k0,
                                                                        ksplit);

            // B desc
            b_grid_desc_b_k0_n_k1_ = MakeBGridDescriptor_KBatch_K0_N_K1(a_g_n_k_wos_lengths,
                                                                        a_g_n_k_wos_strides,
                                                                        b_g_n_c_wis_lengths,
                                                                        b_g_n_c_wis_strides,
                                                                        c_g_k_c_xs_lengths,
                                                                        c_g_k_c_xs_strides,
                                                                        conv_filter_strides,
                                                                        conv_filter_dilations,
                                                                        input_left_pads,
                                                                        input_right_pads,
                                                                        k0,
                                                                        ksplit);

            block_2_ctile_map_ =
                GridwiseGemm::MakeCBlockClusterAdaptor(c_grid_desc_m_n_, M01, N01, ksplit);

            if(GridwiseGemm::CheckValidity(a_grid_desc_b_k0_m_k1_,
                                           b_grid_desc_b_k0_n_k1_,
                                           c_grid_desc_m_n_,
                                           block_2_ctile_map_))
            {
                c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2_ =
                    GridwiseGemm::MakeCGridDescriptor_M0_N0_M1_N1_M2_M3_M4_N2(c_grid_desc_m_n_);
            }
        }

        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;

        ck::index_t num_group_;

        AGridDesc_B_K0_M_K1 a_grid_desc_b_k0_m_k1_;
        BGridDesc_B_K0_N_K1 b_grid_desc_b_k0_n_k1_;
        CGridDesc_M_N c_grid_desc_m_n_;
        CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2 c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2_;

        Block2CTileMap block_2_ctile_map_;

        ComputePtrOffsetOfStridedBatch compute_ptr_offset_of_batch_;

        ck::index_t M01_;
        ck::index_t N01_;

        AElementwiseOperation a_element_op_;
        BElementwiseOperation b_element_op_;
        CElementwiseOperation c_element_op_;

        std::array<ck::index_t, NDimSpatial + 3> a_g_n_k_wos_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> a_g_n_k_wos_strides_;
        std::array<ck::index_t, NDimSpatial + 3> b_g_n_c_wis_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> b_g_n_c_wis_strides_;
        std::array<ck::index_t, NDimSpatial + 3> c_g_k_c_xs_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> c_g_k_c_xs_strides_;
        std::array<ck::index_t, NDimSpatial> conv_filter_strides_;
        std::array<ck::index_t, NDimSpatial> conv_filter_dilations_;
        std::array<ck::index_t, NDimSpatial> input_left_pads_;
        std::array<ck::index_t, NDimSpatial> input_right_pads_;
    };

    struct Invoker : public BaseInvoker
    {
        using Argument = DeviceOp::Argument;

        void ShowInfo(const Argument& arg)
        {
            std::cout << "arg.a_grid_desc_b_k0_m_k1_{" << arg.a_grid_desc_b_k0_m_k1_.GetLength(I0)
                      << ", " << arg.a_grid_desc_b_k0_m_k1_.GetLength(I1) << ", "
                      << arg.a_grid_desc_b_k0_m_k1_.GetLength(I2) << ", "
                      << arg.a_grid_desc_b_k0_m_k1_.GetLength(I3) << "}" << std::endl;

            std::cout << "arg.b_grid_desc_b_k0_n_k1_{" << arg.b_grid_desc_b_k0_n_k1_.GetLength(I0)
                      << ", " << arg.b_grid_desc_b_k0_n_k1_.GetLength(I1) << ", "
                      << arg.b_grid_desc_b_k0_n_k1_.GetLength(I2) << ", "
                      << arg.b_grid_desc_b_k0_n_k1_.GetLength(I3) << "}" << std::endl;

            std::cout << "arg.c_grid_desc_m_n_{" << arg.c_grid_desc_m_n_.GetLength(I0) << ", "
                      << arg.c_grid_desc_m_n_.GetLength(I1) << "}" << std::endl;
        }

        float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {
            if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_b_k0_m_k1_,
                                            arg.b_grid_desc_b_k0_n_k1_,
                                            arg.c_grid_desc_m_n_,
                                            arg.block_2_ctile_map_))
            {
                throw std::runtime_error(
                    "wrong! GridwiseGemm_km_kn_m0m1n0n1_xdlops_v3r1 has invalid setting");
            }

            const index_t grid_size =
                arg.block_2_ctile_map_.CalculateGridSize(arg.c_grid_desc_m_n_) * arg.num_group_;

            const auto K0 = arg.a_grid_desc_b_k0_m_k1_.GetLength(I1);

            const bool has_main_k0_block_loop = GridwiseGemm::CalculateHasMainK0BlockLoop(K0);

            // 16 waves per CU
            constexpr index_t WaveSize      = 64;
            constexpr index_t MinWavePerCu  = 8;
            constexpr index_t WavesPerBlock = BlockSize / WaveSize;
            constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

            auto launch_kernel = [&](auto has_main_k_block_loop) {
                constexpr bool has_main_loop = has_main_k_block_loop.value;

                const auto kernel = kernel_grouped_conv_bwd_weight_mmac<
                    GridwiseGemm,
                    ADataType,
                    BDataType,
                    CDataType,
                    AElementwiseOperation,
                    BElementwiseOperation,
                    CElementwiseOperation,
                    remove_reference_t<typename DeviceOp::AGridDesc_B_K0_M_K1>,
                    remove_reference_t<typename DeviceOp::BGridDesc_B_K0_N_K1>,
                    remove_reference_t<typename DeviceOp::CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2>,
                    remove_reference_t<typename DeviceOp::Block2CTileMap>,
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
                                              arg.a_element_op_,
                                              arg.b_element_op_,
                                              arg.c_element_op_,
                                              arg.num_group_,
                                              arg.a_grid_desc_b_k0_m_k1_,
                                              arg.b_grid_desc_b_k0_n_k1_,
                                              arg.c_grid_desc_m0_n0_m1_n1_m2_m3_m4_n2_,
                                              arg.block_2_ctile_map_,
                                              arg.compute_ptr_offset_of_batch_);
            };

            if(has_main_k0_block_loop)
            {
                return launch_kernel(integral_constant<bool, true>{});
            }
            else
            {
                return launch_kernel(integral_constant<bool, false>{});
            }
        }

        float Run(const BaseArgument* p_arg,
                  const StreamConfig& stream_config = StreamConfig{}) override
        {
            return Run(*dynamic_cast<const Argument*>(p_arg), stream_config);
        }
    };

    static bool IsSupportedArgument(const Argument& arg)
    {
        // device check
        static const auto hcu_target_enum = ck::get_hcu_target_enum();

        if(hcu_target_enum < HCUTargetEnum::HCU_TARGET_GFX928)
        {
            return false;
        }

        const index_t ConvK = arg.c_g_k_c_xs_lengths_[1];
        const index_t ConvC = arg.c_g_k_c_xs_lengths_[2];

        if constexpr(ConvBackwardWeightSpecialization ==
                     ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
        {
            // check if it's 1x1, stride=1 pad = 0 conv
            for(int i = 0; i < NDimSpatial; i++)
            {
                if(!(arg.c_g_k_c_xs_lengths_[i + 3] == 1 && arg.conv_filter_strides_[i] == 1 &&
                     arg.input_left_pads_[i] == 0 && arg.input_right_pads_[i] == 0))
                {
                    return false;
                }
            }
        }

        if constexpr(ConvBackwardWeightSpecialization ==
                     ConvolutionBackwardWeightSpecialization::Filter1x1Pad0)
        {
            // check if it's 1x1,  pad = 0 conv
            for(int i = 0; i < NDimSpatial; i++)
            {
                if(!(arg.c_g_k_c_xs_lengths_[i + 3] == 1 && arg.input_left_pads_[i] == 0 &&
                     arg.input_right_pads_[i] == 0))
                {
                    return false;
                }
            }
        }

        if constexpr(is_same_v<ALayout, tensor_layout::convolution::NHWGK> &&
                     is_same_v<BLayout, tensor_layout::convolution::NHWGC>)
        {
            // vector load A/B matrix from global memory
            if(!(ABlockTransferSrcVectorDim == 2 && BBlockTransferSrcVectorDim == 2 &&
                 ConvK % ABlockTransferSrcScalarPerVector == 0 &&
                 ConvC % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else if constexpr(is_same_v<ALayout, tensor_layout::convolution::NGKHW> &&
                          is_same_v<BLayout, tensor_layout::convolution::NGCHW>)
        {
            const ck::index_t HoWo = arg.a_g_n_k_wos_lengths_[3] * arg.a_g_n_k_wos_lengths_[4];

            if(!(ABlockTransferSrcVectorDim == 3 && HoWo % ABlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }

            if constexpr(ConvBackwardWeightSpecialization ==
                         ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0)
            {
                if(!(BBlockTransferSrcVectorDim == 3 &&
                     HoWo % BBlockTransferSrcScalarPerVector == 0))
                {
                    return false;
                }
            }
            else
            {
                if(!(BBlockTransferSrcScalarPerVector == 1))
                {
                    return false;
                }
            }
        }
        else if constexpr(is_same_v<ALayout, tensor_layout::convolution::NGKHWk32> &&
                          is_same_v<BLayout, tensor_layout::convolution::NGCHWc32>)
        {
            // vector load A/B matrix from global memory
            if constexpr(!(ABlockTransferSrcVectorDim == 2 && BBlockTransferSrcVectorDim == 2 &&
                           32 % ABlockTransferSrcScalarPerVector == 0 &&
                           32 % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        if(!(is_same_v<CLayout, tensor_layout::convolution::GKYXC> ||
             is_same_v<CLayout, tensor_layout::convolution::GKCYX> ||
             is_same_v<CLayout, tensor_layout::convolution::GKCYXc32>))
        {
            return false;
        }

        // Gridwise GEMM size
        return GridwiseGemm::CheckValidity(arg.a_grid_desc_b_k0_m_k1_,
                                           arg.b_grid_desc_b_k0_n_k1_,
                                           arg.c_grid_desc_m_n_,
                                           arg.block_2_ctile_map_);
    }

    bool IsSupportedArgument(const BaseArgument* p_arg) override
    {
        return IsSupportedArgument(*dynamic_cast<const Argument*>(p_arg));
    }

    static auto MakeArgument(const void* p_a, // output
                             const void* p_b, // input
                             void* p_c,       // weight
                             const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
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
                        a_g_n_k_wos_lengths,
                        a_g_n_k_wos_strides,
                        b_g_n_c_wis_lengths,
                        b_g_n_c_wis_strides,
                        c_g_k_c_xs_lengths,
                        c_g_k_c_xs_strides,
                        conv_filter_strides,
                        conv_filter_dilations,
                        input_left_pads,
                        input_right_pads,
                        a_element_op,
                        b_element_op,
                        c_element_op,
                        1,
                        1);
    }

    std::unique_ptr<BaseArgument>
    MakeArgumentPointer(const void* p_a, // output
                        const void* p_b, // input
                        void* p_c,       // weight
                        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
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
                                          a_g_n_k_wos_lengths,
                                          a_g_n_k_wos_strides,
                                          b_g_n_c_wis_lengths,
                                          b_g_n_c_wis_strides,
                                          c_g_k_c_xs_lengths,
                                          c_g_k_c_xs_strides,
                                          conv_filter_strides,
                                          conv_filter_dilations,
                                          input_left_pads,
                                          input_right_pads,
                                          a_element_op,
                                          b_element_op,
                                          c_element_op,
                                          1,
                                          1);
    }

    std::unique_ptr<BaseInvoker> MakeInvokerPointer() override
    {
        return std::make_unique<Invoker>(Invoker{});
    }

    static auto MakeInvoker() { return Invoker{}; }

    std::string GetTypeString() const override
    {
        auto str = std::stringstream();

        // WARNING: miopen can't get complement type string with comma, never use it!!
        // clang-format off
            str << "DeviceGroupedConvBwdWeight_Mmac"
                << "-"
                << BlockSize << "-"
                << MPerBlock << "-"
                << NPerBlock << "-"
                << K0PerBlock << "-"
                << getConvBackwardWeightSpecializationString(ConvBackwardWeightSpecialization) << "-"
                << K1 << "-"
                << MMmacPerWave << "-"
                << NMmacPerWave << "-"
                << ABlockTransferSrcScalarPerVector << "-"
                << ABlockTransferDstScalarPerVector_K1 << "-"
                << BBlockTransferSrcScalarPerVector << "-"
                << BBlockTransferDstScalarPerVector_K1 << "-"
                << NumGemmKPrefetchStage << "-"
                << GemmKSplitFactor;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
