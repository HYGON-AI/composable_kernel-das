// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <iostream>
#include <cmath>
#include <numeric>
#include <sstream>
#include <type_traits>

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/device_grouped_conv_bwd_data.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_data_specialization.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_nt_m0k0k1m1_n0k0k1n1_nm_v1_cshuffle.hpp"
#include "ck/tensor_operation/operator_transform/transform_conv_bwd_data_to_gemm_v2.hpp"
#include "ck/host_utility/device_prop.hpp"
#include "ck/host_utility/io.hpp"
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
          typename AGridDesc_B_M0_K0_K1_M1,
          typename BGridDesc_B_N0_K0_K1_N1,
          typename CShuffleGridDesc_N0_N1_N2_M0_M1_M2,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename Block2CTileMap,
          typename ComputePtrOffsetOfBatch,
          bool HasMainKBlockLoop,
          ck::index_t MaxThreadPerBlock = CK_MAX_THREAD_PER_BLOCK,
          ck::index_t MinBlockPerCU     = CK_MIN_BLOCK_PER_CU>
__global__ void
#if CK_USE_LAUNCH_BOUNDS
__launch_bounds__(MaxThreadPerBlock, MinBlockPerCU)
#endif
    kernel_grouped_conv_bwd_data_mmac_nchw_v2_cshuffle(
        const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const AGridDesc_B_M0_K0_K1_M1 a_b_m0_k0_k1_m1_grid_desc,
        const BGridDesc_B_N0_K0_K1_N1 b_b_n0_k0_k1_n1_grid_desc,
        const CShuffleGridDesc_N0_N1_N2_M0_M1_M2 cshuffle_grid_desc_n0_n1_n2_m0_m1_m2,
        const AElementwiseOperation a_element_op,
        const BElementwiseOperation b_element_op,
        const CElementwiseOperation c_element_op,
        const ck::index_t group_count,
        const Block2CTileMap block_2_ctile_map,
        const ComputePtrOffsetOfBatch compute_ptr_offset_of_batch)
{
#if(!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
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
                                                  a_b_m0_k0_k1_m1_grid_desc,
                                                  b_b_n0_k0_k1_n1_grid_desc,
                                                  cshuffle_grid_desc_n0_n1_n2_m0_m1_m2,
                                                  a_element_op,
                                                  b_element_op,
                                                  c_element_op,
                                                  block_2_ctile_map);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = a_b_m0_k0_k1_m1_grid_desc;
    ignore = b_b_n0_k0_k1_n1_grid_desc;
    ignore = cshuffle_grid_desc_n0_n1_n2_m0_m1_m2;
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
          ConvolutionBackwardDataSpecialization ConvBwdDataSpecialization,
          ck::index_t BlockSize,
          ck::index_t M0PerBlock,
          ck::index_t M1PerBlock,
          ck::index_t N0PerBlock,
          ck::index_t N1PerBlock,
          ck::index_t K0PerBlock,
          ck::index_t K1PerBlock,
          ck::index_t MPerMmac,
          ck::index_t NPerMmac,
          ck::index_t MwaveRepeat,
          ck::index_t NwaveRepeat,
          ck::index_t MmmacRepeat,
          ck::index_t NmmacRepeat,
          ck::index_t MmmacInterleave,
          ck::index_t NmmacInterleave,
          typename ABlockTransferThreadClusterLengths_B_M0_K0_K1_M1,
          ck::index_t ABlockTransferSrcVectorDim,
          ck::index_t ABlockTransferSrcScalarPerVector,
          typename BBlockTransferThreadClusterLengths_B_N0_K0_K1_N1,
          ck::index_t BBlockTransferSrcVectorDim,
          ck::index_t BBlockTransferSrcScalarPerVector,
          index_t CShuffleMwaveRepeatPerShuffle,
          index_t CShuffleNwaveRepeatPerShuffle,
          typename CShuffleBlockTransferClusterLengths_N0_N1_N2_M0_M1_M2,
          index_t CShuffleBlockTransferDstScalarPerVector,
          ck::index_t NumGemmKPrefetchStage>
struct DeviceGroupedConvBwdData_mmac_nchw_v2_cshuffle
    : public DeviceGroupedConvBwdData<NDimSpatial,
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
    using DeviceOp = DeviceGroupedConvBwdData_mmac_nchw_v2_cshuffle;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};

    static constexpr ck::index_t MPerBlock = M0PerBlock * M1PerBlock;
    static constexpr ck::index_t NPerBlock = N0PerBlock * N1PerBlock;
    static constexpr ck::index_t KPerBlock = K0PerBlock * K1PerBlock;

    static constexpr auto conv_to_gemm_transformer =
        TransformConvBwdDataToGemm_v2<NDimSpatial, ConvBwdDataSpecialization>{};

    static constexpr auto matrix_padder =
        MatrixPadder<GemmSpecialization::MNKPadding, ck::index_t, ck::index_t, ck::index_t>{
            MPerBlock, NPerBlock, KPerBlock};

    static auto MakeAGridDescriptor_B_M0_K0_K1_M1(
        const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
        const std::array<ck::index_t, NDimSpatial>& input_left_pads,
        const std::array<ck::index_t, NDimSpatial>& input_right_pads,
        const std::array<ck::index_t, NDimSpatial>& tildes)
    {
        const auto in_gemmmraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeADescriptor_M_K<ALayout>(out_g_n_k_wos_lengths,
                                                                           out_g_n_k_wos_strides,
                                                                           wei_g_k_c_xs_lengths,
                                                                           wei_g_k_c_xs_strides,
                                                                           in_g_n_c_wis_lengths,
                                                                           in_g_n_c_wis_strides,
                                                                           conv_filter_strides,
                                                                           conv_filter_dilations,
                                                                           input_left_pads,
                                                                           input_right_pads,
                                                                           tildes[0],
                                                                           tildes[1]);

        const auto in_gemmm_gemmk_desc =
            matrix_padder.PadADescriptor_M_K(in_gemmmraw_gemmkraw_desc);

        const ck::index_t gemm_m = in_gemmm_gemmk_desc.GetLength(I0);
        const ck::index_t gemm_k = in_gemmm_gemmk_desc.GetLength(I1);

        const auto in_b_gemmm0_gemmk0_gemmk1_gemmm1_desc = transform_tensor_descriptor(
            in_gemmm_gemmk_desc,
            make_tuple(make_unmerge_transform(make_tuple(gemm_m / M1PerBlock, M1PerBlock)),
                       make_unmerge_transform(make_tuple(1, gemm_k / K1PerBlock, K1PerBlock))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<1, 4>{}, Sequence<0, 2, 3>{}));

        return in_b_gemmm0_gemmk0_gemmk1_gemmm1_desc;
    }

    static auto MakeBGridDescriptor_B_N0_K0_K1_N1(
        const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_strides,
        const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
        const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
        const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
        const std::array<ck::index_t, NDimSpatial>& input_left_pads,
        const std::array<ck::index_t, NDimSpatial>& input_right_pads,
        const std::array<ck::index_t, NDimSpatial>& tildes)
    {
        const auto wei_gemmnraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeBDescriptor_N_K<BLayout>(out_g_n_k_wos_lengths,
                                                                           out_g_n_k_wos_strides,
                                                                           wei_g_k_c_xs_lengths,
                                                                           wei_g_k_c_xs_strides,
                                                                           in_g_n_c_wis_lengths,
                                                                           in_g_n_c_wis_strides,
                                                                           conv_filter_strides,
                                                                           conv_filter_dilations,
                                                                           input_left_pads,
                                                                           input_right_pads,
                                                                           tildes[0],
                                                                           tildes[1]);

        const auto wei_gemmn_gemmk_desc =
            matrix_padder.PadBDescriptor_N_K(wei_gemmnraw_gemmkraw_desc);

        const ck::index_t gemm_n = wei_gemmn_gemmk_desc.GetLength(I0);
        const ck::index_t gemm_k = wei_gemmn_gemmk_desc.GetLength(I1);

        const auto wei_b_gemmn0_gemmk0_gemmk1_gemmn1_desc = transform_tensor_descriptor(
            wei_gemmn_gemmk_desc,
            make_tuple(make_unmerge_transform(make_tuple(gemm_n / N1PerBlock, N1PerBlock)),
                       make_unmerge_transform(make_tuple(1, gemm_k / K1PerBlock, K1PerBlock))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<1, 4>{}, Sequence<0, 2, 3>{}));

        return wei_b_gemmn0_gemmk0_gemmk1_gemmn1_desc;
    }

    static auto
    MakeCGridDescriptor_M_N(const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
                            const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_strides,
                            const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                            const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                            const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                            const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                            const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                            const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                            const std::array<ck::index_t, NDimSpatial>& tildes)
    {
        const auto out_gemmmraw_gemmnraw_desc =
            conv_to_gemm_transformer.template MakeCDescriptor_M_N<CLayout>(out_g_n_k_wos_lengths,
                                                                           out_g_n_k_wos_strides,
                                                                           wei_g_k_c_xs_lengths,
                                                                           wei_g_k_c_xs_strides,
                                                                           in_g_n_c_wis_lengths,
                                                                           in_g_n_c_wis_strides,
                                                                           conv_filter_strides,
                                                                           conv_filter_dilations,
                                                                           input_left_pads,
                                                                           input_right_pads,
                                                                           tildes[0],
                                                                           tildes[1]);

        const auto out_gemmm_gemmn_desc =
            matrix_padder.PadCDescriptor_M_N(out_gemmmraw_gemmnraw_desc);

        return out_gemmm_gemmn_desc;
    }

    using AGridDesc_B_M0_K0_K1_M1 = remove_cvref_t<decltype(MakeAGridDescriptor_B_M0_K0_K1_M1(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    using BGridDesc_B_N0_K0_K1_N1 = remove_cvref_t<decltype(MakeBGridDescriptor_B_N0_K0_K1_N1(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    using CGridDesc_M_N           = remove_cvref_t<decltype(MakeCGridDescriptor_M_N(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;

    using GridwiseGemm = GridwiseGemm_mmac_nt_m0k0k1m1_n0k0k1n1_nm_v1_cshuffle<
        BlockSize,
        ADataType,
        BDataType,
        AccDataType,
        CDataType,
        InMemoryDataOperationEnum::Set,
        AElementwiseOperation,
        BElementwiseOperation,
        CElementwiseOperation,
        AGridDesc_B_M0_K0_K1_M1,
        BGridDesc_B_N0_K0_K1_N1,
        CGridDesc_M_N,
        M0PerBlock,
        M1PerBlock,
        N0PerBlock,
        N1PerBlock,
        K0PerBlock,
        K1PerBlock,
        MPerMmac,
        NPerMmac,
        MwaveRepeat,
        NwaveRepeat,
        MmmacRepeat,
        NmmacRepeat,
        MmmacInterleave,
        NmmacInterleave,
        ABlockTransferThreadClusterLengths_B_M0_K0_K1_M1,
        ABlockTransferSrcVectorDim,
        ABlockTransferSrcScalarPerVector,
        BBlockTransferThreadClusterLengths_B_N0_K0_K1_N1,
        BBlockTransferSrcVectorDim,
        BBlockTransferSrcScalarPerVector,
        CShuffleMwaveRepeatPerShuffle,
        CShuffleNwaveRepeatPerShuffle,
        CShuffleBlockTransferClusterLengths_N0_N1_N2_M0_M1_M2,
        CShuffleBlockTransferDstScalarPerVector,
        NumGemmKPrefetchStage>;

    struct Argument : public BaseArgument
    {
        Argument(const void* p_a,
                 const void* p_b,
                 void* p_c,
                 const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_c_wis_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& c_g_n_c_wis_strides,
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
              num_group_(a_g_n_k_wos_lengths[0]),
              a_grid_desc_b_m0_k0_k1_m1_container_(),
              b_grid_desc_b_n0_k0_k1_n1_container_(),
              c_grid_desc_m_n_container_(),
              cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_container_(),
              block_2_ctile_map_container_(),
              compute_ptr_offset_of_batch_(),
              M01_(M01),
              N01_(N01),
              a_element_op_(a_element_op),
              b_element_op_(b_element_op),
              c_element_op_(c_element_op),
              a_g_n_k_wos_lengths_{a_g_n_k_wos_lengths},
              a_g_n_k_wos_strides_{a_g_n_k_wos_strides},
              b_g_k_c_xs_lengths_{b_g_k_c_xs_lengths},
              b_g_k_c_xs_strides_{b_g_k_c_xs_strides},
              c_g_n_c_wis_lengths_{c_g_n_c_wis_lengths},
              c_g_n_c_wis_strides_{c_g_n_c_wis_strides},
              conv_filter_strides_{conv_filter_strides},
              conv_filter_dilations_{conv_filter_dilations},
              input_left_pads_{input_left_pads},
              input_right_pads_{input_right_pads}
        {
            // A/B/C Batch Stride
            compute_ptr_offset_of_batch_.BatchStrideA_ = a_g_n_k_wos_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideB_ = b_g_k_c_xs_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideC_ = c_g_n_c_wis_strides[0];

            // problem definition
            const ck::index_t Y = b_g_k_c_xs_lengths[3];
            const ck::index_t X = b_g_k_c_xs_lengths[4];

            const ck::index_t ConvStrideH = conv_filter_strides_[0];
            const ck::index_t ConvStrideW = conv_filter_strides_[1];

            const ck::index_t ConvDilationH = conv_filter_dilations_[0];
            const ck::index_t ConvDilationW = conv_filter_dilations_[1];

            const auto GcdStrideDilationH = math::gcd(ConvStrideH, ConvDilationH);
            const auto GcdStrideDilationW = math::gcd(ConvStrideW, ConvDilationW);

            const auto YTilde = ConvStrideH / GcdStrideDilationH;
            const auto XTilde = ConvStrideW / GcdStrideDilationW;

            // number of GEMM
            num_gemm_ = YTilde * XTilde;

            for(ck::index_t i_ytilde = 0; i_ytilde < YTilde; ++i_ytilde)
            {
                for(ck::index_t i_xtilde = 0; i_xtilde < XTilde; ++i_xtilde)
                {
                    // check slice is valid
                    const auto YDotSlice = math::integer_divide_ceil(Y - i_ytilde, YTilde);
                    const auto XDotSlice = math::integer_divide_ceil(X - i_xtilde, XTilde);

                    if(YDotSlice * XDotSlice <= 0)
                    {
                        --num_gemm_;
                        continue;
                    }

                    // Gemm A (dout)
                    const auto a_grid_desc_b_m0_k0_k1_m1 =
                        MakeAGridDescriptor_B_M0_K0_K1_M1(a_g_n_k_wos_lengths,
                                                          a_g_n_k_wos_strides,
                                                          b_g_k_c_xs_lengths,
                                                          b_g_k_c_xs_strides,
                                                          c_g_n_c_wis_lengths,
                                                          c_g_n_c_wis_strides,
                                                          conv_filter_strides,
                                                          conv_filter_dilations,
                                                          input_left_pads,
                                                          input_right_pads,
                                                          {i_ytilde, i_xtilde});

                    // Gemm B (weight)
                    const auto b_grid_desc_b_n0_k0_k1_n1 =
                        MakeBGridDescriptor_B_N0_K0_K1_N1(a_g_n_k_wos_lengths,
                                                          a_g_n_k_wos_strides,
                                                          b_g_k_c_xs_lengths,
                                                          b_g_k_c_xs_strides,
                                                          c_g_n_c_wis_lengths,
                                                          c_g_n_c_wis_strides,
                                                          conv_filter_strides,
                                                          conv_filter_dilations,
                                                          input_left_pads,
                                                          input_right_pads,
                                                          {i_ytilde, i_xtilde});

                    // Gemm C (dinput)
                    const auto c_grid_desc_m_n = MakeCGridDescriptor_M_N(a_g_n_k_wos_lengths,
                                                                         a_g_n_k_wos_strides,
                                                                         b_g_k_c_xs_lengths,
                                                                         b_g_k_c_xs_strides,
                                                                         c_g_n_c_wis_lengths,
                                                                         c_g_n_c_wis_strides,
                                                                         conv_filter_strides,
                                                                         conv_filter_dilations,
                                                                         input_left_pads,
                                                                         input_right_pads,
                                                                         {i_ytilde, i_xtilde});

                    a_grid_desc_b_m0_k0_k1_m1_container_.push_back(a_grid_desc_b_m0_k0_k1_m1);
                    b_grid_desc_b_n0_k0_k1_n1_container_.push_back(b_grid_desc_b_n0_k0_k1_n1);
                    c_grid_desc_m_n_container_.push_back(c_grid_desc_m_n);

                    auto block_2_ctile_map =
                        GridwiseGemm::MakeDefaultBlock2CTileMap(c_grid_desc_m_n, M01, N01, 1);
                    block_2_ctile_map_container_.push_back(block_2_ctile_map);

                    if(GridwiseGemm::CheckValidity(a_grid_desc_b_m0_k0_k1_m1,
                                                   b_grid_desc_b_n0_k0_k1_n1,
                                                   c_grid_desc_m_n,
                                                   block_2_ctile_map))
                    {
                        cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_container_.push_back(
                            GridwiseGemm::MakeCShuffleGridDescriptor_N0_N1_N2_M0_M1_M2(
                                c_grid_desc_m_n));
                    }
                }
            }
        }

        void Print() const
        {
            for(ck::index_t i = 0; i < num_gemm_; ++i)
            {
                const auto a_grid_desc_k0_m_k1 = a_grid_desc_b_m0_k0_k1_m1_container_[i];
                const auto b_grid_desc_k0_n_k1 = b_grid_desc_b_n0_k0_k1_n1_container_[i];
                const auto c_grid_desc_m_n     = c_grid_desc_m_n_container_[i];
                const auto cshuffle_grid_desc_n0_n1_n2_m0_m1_m2 =
                    cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_container_[i];

                std::cout << "Gemm: " << i << std::endl;
                std::cout << "A[B, M, K]: " << a_grid_desc_k0_m_k1 << std::endl;
                std::cout << "B[B, N0, K0, K1, N1]: " << b_grid_desc_k0_n_k1 << std::endl;
                std::cout << "C[M, N]: " << c_grid_desc_m_n << std::endl;
                std::cout << "CShuffle: " << cshuffle_grid_desc_n0_n1_n2_m0_m1_m2 << std::endl;
            }
        }

        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;

        ck::index_t num_group_;
        ck::index_t num_gemm_;
        std::vector<AGridDesc_B_M0_K0_K1_M1> a_grid_desc_b_m0_k0_k1_m1_container_;
        std::vector<BGridDesc_B_N0_K0_K1_N1> b_grid_desc_b_n0_k0_k1_n1_container_;
        std::vector<CGridDesc_M_N> c_grid_desc_m_n_container_;
        std::vector<typename GridwiseGemm::CShuffleGridDesc_N0_N1_N2_M0_M1_M2>
            cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_container_;
        std::vector<typename GridwiseGemm::DefaultBlock2CTileMap> block_2_ctile_map_container_;
        ComputePtrOffsetOfStridedBatch compute_ptr_offset_of_batch_;
        ck::index_t M01_;
        ck::index_t N01_;

        // elementwise op
        AElementwiseOperation a_element_op_;
        BElementwiseOperation b_element_op_;
        CElementwiseOperation c_element_op_;

        // conv problem desc
        std::array<ck::index_t, NDimSpatial + 3> a_g_n_k_wos_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> a_g_n_k_wos_strides_;
        std::array<ck::index_t, NDimSpatial + 3> b_g_k_c_xs_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> b_g_k_c_xs_strides_;
        std::array<ck::index_t, NDimSpatial + 3> c_g_n_c_wis_lengths_;
        std::array<ck::index_t, NDimSpatial + 3> c_g_n_c_wis_strides_;
        std::array<ck::index_t, NDimSpatial> conv_filter_strides_;
        std::array<ck::index_t, NDimSpatial> conv_filter_dilations_;
        std::array<ck::index_t, NDimSpatial> input_left_pads_;
        std::array<ck::index_t, NDimSpatial> input_right_pads_;
    };
    struct Invoker : public BaseInvoker
    {
        using Argument = DeviceOp::Argument;

        float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {
            if(stream_config.log_level_ > 0)
            {
                arg.Print();
            }

            // 16 waves per CU
            constexpr index_t WaveSize      = 64;
            constexpr index_t MinWavePerCu  = 8;
            constexpr index_t WavesPerBlock = BlockSize / WaveSize;
            constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

            float ave_time = 0.0f;

            for(ck::index_t i = 0; i < arg.num_gemm_; ++i)
            {
                if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_b_m0_k0_k1_m1_container_[i],
                                                arg.b_grid_desc_b_n0_k0_k1_n1_container_[i],
                                                arg.c_grid_desc_m_n_container_[i],
                                                arg.block_2_ctile_map_container_[i]))
                {
                    throw std::runtime_error(
                        "wrong! GridwiseGemm_mmac_nt_m0k0k1m1_n0k0k1n1_nm_v1_cshuffle has invalid "
                        "setting");
                }

                const ck::index_t grid_size = arg.block_2_ctile_map_container_[i].CalculateGridSize(
                                                  arg.c_grid_desc_m_n_container_[i]) *
                                              arg.num_group_;

                const auto K = arg.a_grid_desc_b_m0_k0_k1_m1_container_[i].GetLength(I2) *
                               arg.a_grid_desc_b_m0_k0_k1_m1_container_[i].GetLength(I3);

                const bool has_main_k_block_loop = GridwiseGemm::CalculateHasMainKBlockLoop(K);

                auto launch_kernel = [&](auto has_main_k_block_loop_) {
                    constexpr bool has_main_loop = has_main_k_block_loop_.value;

                    const auto kernel = kernel_grouped_conv_bwd_data_mmac_nchw_v2_cshuffle<
                        GridwiseGemm,
                        ADataType,
                        BDataType,
                        CDataType,
                        remove_reference_t<DeviceOp::AGridDesc_B_M0_K0_K1_M1>,
                        remove_reference_t<DeviceOp::BGridDesc_B_N0_K0_K1_N1>,
                        remove_reference_t<
                            typename GridwiseGemm::CShuffleGridDesc_N0_N1_N2_M0_M1_M2>,
                        AElementwiseOperation,
                        BElementwiseOperation,
                        CElementwiseOperation,
                        remove_reference_t<typename GridwiseGemm::DefaultBlock2CTileMap>,
                        ComputePtrOffsetOfStridedBatch,
                        has_main_loop,
                        BlockSize,
                        MinBlockPerCU>;

                    return launch_and_time_kernel(
                        stream_config,
                        kernel,
                        dim3(grid_size),
                        dim3(BlockSize),
                        0,
                        arg.p_a_grid_,
                        arg.p_b_grid_,
                        arg.p_c_grid_,
                        arg.a_grid_desc_b_m0_k0_k1_m1_container_[i],
                        arg.b_grid_desc_b_n0_k0_k1_n1_container_[i],
                        arg.cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_container_[i],
                        arg.a_element_op_,
                        arg.b_element_op_,
                        arg.c_element_op_,
                        arg.num_group_,
                        arg.block_2_ctile_map_container_[i],
                        arg.compute_ptr_offset_of_batch_);
                };

                if(has_main_k_block_loop)
                {
                    ave_time += launch_kernel(integral_constant<bool, true>{});
                }
                else
                {
                    ave_time += launch_kernel(integral_constant<bool, false>{});
                }
            }
            return ave_time;
        }

        float Run(const BaseArgument* p_arg,
                  const StreamConfig& stream_config = StreamConfig{}) override
        {
            return Run(*dynamic_cast<const Argument*>(p_arg), stream_config);
        }
    };

    static bool IsSupportedArgument(const Argument& arg)
    {
        namespace ctc = ck::tensor_layout::convolution;

        // device check
        static const auto hcu_target_enum = ck::get_hcu_target_enum();

        if(hcu_target_enum < HCUTargetEnum::HCU_TARGET_GFX928)
        {
            return false;
        }

        // This NCHW transform maps only one image into the GEMM M dimension. For N > 1 the
        // batch stride is not represented by the generated descriptors and the kernel silently
        // mixes images, so reject that unsupported case instead of returning incorrect data.
        if(arg.a_g_n_k_wos_lengths_[1] != 1 || arg.c_g_n_c_wis_lengths_[1] != 1)
        {
            return false;
        }

        // Specifialization
        if constexpr(ConvBwdDataSpecialization ==
                     ConvolutionBackwardDataSpecialization::Filter1x1Stride1Pad0)
        {
            // check if it's 1x1, stride=1 pad = 0 conv
            for(int i = 0; i < NDimSpatial; i++)
            {
                if(!(arg.b_g_k_c_xs_lengths_[3 + i] == 1 && arg.conv_filter_strides_[i] == 1 &&
                     arg.input_left_pads_[i] == 0 && arg.input_right_pads_[i] == 0))
                {
                    return false;
                }
            }
        }
        else
        {
            // TODO: only support 1x1s1p0 conv fwd for now
            return false;
        }

        // Gemm A (doutput)
        if constexpr(is_same_v<ALayout, ctc::NGKHW>)
        {
            const ck::index_t HiWi = arg.c_g_n_c_wis_lengths_[3] * arg.c_g_n_c_wis_lengths_[4];
            // vector load along gemm m (HiWi)
            if(!(ABlockTransferSrcVectorDim == 4 && HiWi % ABlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }

        else
        {
            return false;
        }

        // Gemm B (weight)
        if constexpr(is_same_v<BLayout, ctc::GKCYX>)
        {
            const ck::index_t ConvC = arg.b_g_k_c_xs_lengths_[2];
            // vector load along gemm n (ConvC)
            if(!(BBlockTransferSrcVectorDim == 4 && ConvC % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // Gemm C (dinput)
        if constexpr(is_same_v<CLayout, ctc::NGCHW>)
        {
            const ck::index_t HiWi = arg.c_g_n_c_wis_lengths_[3] * arg.c_g_n_c_wis_lengths_[4];
            // vector store along gemm m (HiWi)
            if(!(HiWi % CShuffleBlockTransferDstScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // Gridwise GEMM size
        for(ck::index_t i = 0; i < arg.num_gemm_; i++)
        {
            if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_b_m0_k0_k1_m1_container_[i],
                                            arg.b_grid_desc_b_n0_k0_k1_n1_container_[i],
                                            arg.c_grid_desc_m_n_container_[i],
                                            arg.block_2_ctile_map_container_[i]))
            {
                return false;
            }
        }

        return true;
    }

    bool IsSupportedArgument(const BaseArgument* p_arg) override
    {
        return IsSupportedArgument(*dynamic_cast<const Argument*>(p_arg));
    }

    static auto MakeArgument(const void* p_a,
                             const void* p_b,
                             void* p_c,
                             const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_c_wis_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& c_g_c_wis_strides,
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
                        b_g_k_c_xs_lengths,
                        b_g_k_c_xs_strides,
                        c_g_c_wis_lengths,
                        c_g_c_wis_strides,
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
                        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& c_g_c_wis_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& c_g_c_wis_strides,
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
                                          b_g_k_c_xs_lengths,
                                          b_g_k_c_xs_strides,
                                          c_g_c_wis_lengths,
                                          c_g_c_wis_strides,
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

        // clang-format off
        str << "DeviceGroupedConvBwdData_mmac_nchw_v2_cshuffle"
            << "-"
            << BlockSize << "-"
            << M0PerBlock << "-"
            << M1PerBlock << "-"
            << N0PerBlock << "-"
            << N1PerBlock << "-"
            << K0PerBlock << "-"
            << K1PerBlock << "-"
            << getConvBackwardDataSpecializationString(ConvBwdDataSpecialization) << "-"
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
            << NumGemmKPrefetchStage;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
