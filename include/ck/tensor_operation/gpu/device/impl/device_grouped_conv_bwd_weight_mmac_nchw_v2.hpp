// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

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
#include "ck/tensor_operation/gpu/device/device_grouped_conv_bwd_weight.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_weight_specialization.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_tn_mk_nk_mn_v2.hpp"
#include "ck/tensor_operation/operator_transform/transform_conv_bwd_weight_to_gemm.hpp"
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
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename AGridDesc_B_M_K,
          typename BGridDesc_B_N_K,
          typename CGridDescInterleaved,
          typename Block2CTileMap,
          typename ComputePtrOffsetOfBatch,
          bool HasMainKBlockLoop,
          ck::index_t MaxThreadPerBlock = CK_MAX_THREAD_PER_BLOCK,
          ck::index_t MinBlockPerCU     = CK_MIN_BLOCK_PER_CU>
__global__ void
#if CK_USE_LAUNCH_BOUNDS
__launch_bounds__(MaxThreadPerBlock, MinBlockPerCU)
#endif
    kernel_grouped_conv_bwd_weight_mmac_nchw_v2(
        const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const AElementwiseOperation a_element_op,
        const BElementwiseOperation b_element_op,
        const CElementwiseOperation c_element_op,
        const ck::index_t group_count,
        const AGridDesc_B_M_K a_grid_desc_b_m_k,
        const BGridDesc_B_N_K b_grid_desc_b_n_k,
        const CGridDescInterleaved c_grid_desc_interleaved,
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
                                                  a_grid_desc_b_m_k,
                                                  b_grid_desc_b_n_k,
                                                  c_grid_desc_interleaved,
                                                  a_element_op,
                                                  b_element_op,
                                                  c_element_op,
                                                  block_2_ctile_map);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = a_grid_desc_b_m_k;
    ignore = b_grid_desc_b_n_k;
    ignore = c_grid_desc_interleaved;
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
          ck::index_t KPerBlock,
          ck::index_t KPack,
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
          ck::index_t NumGemmKPrefetchStage,
          ck::index_t GemmKSplitFactor = 4>
struct DeviceGroupedConvBwdWeight_mmac_nchw_v2
    : public DeviceGroupedConvBwdWeightV2<NDimSpatial,
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
    using DeviceOp = DeviceGroupedConvBwdWeight_mmac_nchw_v2;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};
    static constexpr auto I3 = Number<3>{};

    static constexpr auto conv_to_gemm_transformer =
        TransformConvBwdWeightToGemm<NDimSpatial, ConvBackwardWeightSpecialization>{};

    static constexpr auto matrix_padder =
        MatrixPadder<GemmSpecialization::MNKPadding, ck::index_t, ck::index_t, ck::index_t>{
            MPerBlock, NPerBlock, KPerBlock};

    static auto
    MakeAGridDescriptor_B_M_K(const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                              const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
                              const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                              const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                              const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                              const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                              const ck::index_t splitk)
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

        const auto out_gemmm_gemmk_desc =
            matrix_padder.PadADescriptor_M_K(out_gemmmraw_gemmkraw_desc);

        const ck::index_t gemm_m             = out_gemmm_gemmk_desc.GetLength(I0);
        const ck::index_t gemm_k             = out_gemmm_gemmk_desc.GetLength(I1);
        const ck::index_t gemm_k_with_splitk = gemm_k / splitk;

        const auto out_b_gemmm_gemmk_desc = transform_tensor_descriptor(
            out_gemmm_gemmk_desc,
            make_tuple(make_pass_through_transform(gemm_m),
                       make_unmerge_transform(make_tuple(splitk, gemm_k_with_splitk))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<1>{}, Sequence<0, 2>{}));

        return out_b_gemmm_gemmk_desc;
    }

    static auto
    MakeBGridDescriptor_B_N_K(const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_k_wos_strides,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& b_g_n_c_wis_strides,
                              const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_lengths,
                              const std::array<ck::index_t, NDimSpatial + 3>& c_g_k_c_xs_strides,
                              const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                              const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                              const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                              const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                              const ck::index_t splitk)
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

        const auto in_gemmn_gemmk_desc =
            matrix_padder.PadBDescriptor_N_K(in_gemmnraw_gemmkraw_desc);

        const ck::index_t gemm_n             = in_gemmn_gemmk_desc.GetLength(I0);
        const ck::index_t gemm_k             = in_gemmn_gemmk_desc.GetLength(I1);
        const ck::index_t gemm_k_with_splitk = gemm_k / splitk;

        const auto in_b_gemmn_gemmk_desc = transform_tensor_descriptor(
            in_gemmn_gemmk_desc,
            make_tuple(make_pass_through_transform(gemm_n),
                       make_unmerge_transform(make_tuple(splitk, gemm_k_with_splitk))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<1>{}, Sequence<0, 2>{}));

        return in_b_gemmn_gemmk_desc;
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

    using AGridDesc_B_M_K = remove_cvref_t<decltype(MakeAGridDescriptor_B_M_K(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, 1))>;
    using BGridDesc_B_N_K = remove_cvref_t<decltype(MakeBGridDescriptor_B_N_K(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, 1))>;
    using CGridDesc_M_N =
        remove_cvref_t<decltype(MakeCGridDescriptor_M_N({}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;

    using GridwiseGemm = GridwiseGemm_mmac_tn_mk_nk_mn_v2<BlockSize,
                                                          ADataType,
                                                          BDataType,
                                                          AccDataType,
                                                          CDataType,
                                                          InMemoryDataOperationEnum::AtomicAdd,
                                                          AElementwiseOperation,
                                                          BElementwiseOperation,
                                                          CElementwiseOperation,
                                                          AGridDesc_B_M_K,
                                                          BGridDesc_B_N_K,
                                                          CGridDesc_M_N,
                                                          MPerBlock,
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
                                                          1,
                                                          NumGemmKPrefetchStage>;

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
              a_grid_desc_b_m_k_(),
              b_grid_desc_b_n_k_(),
              c_grid_desc_m_n_(),
              c_grid_desc_interleaved_(),
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

            // heuristic splitk
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

            const ck::index_t grid_size_without_splitk =
                num_group_ * (gemm_m / MPerBlock) * (gemm_n / NPerBlock);

            const ck::index_t max_grid_size = GemmKSplitFactor * ck_tile::get_num_cu();
            ck::index_t splitk              = -1;
            splitk = math::max(max_grid_size / grid_size_without_splitk, 1);

            const ck::index_t n  = a_g_n_k_wos_lengths_[1];
            const ck::index_t ho = a_g_n_k_wos_lengths_[3];
            const ck::index_t wo = a_g_n_k_wos_lengths_[4];

            // splitk should not be greater than batchsize
            // to ensure correctness of vector load among gemm k dimension
            splitk = math::min(splitk, n);

            const ck::index_t gemm_k_without_splitk =
                std::ceil((n * ho * wo) / KPerBlock) * KPerBlock;

            for(; splitk > 1; splitk--)
            {
                if(gemm_k_without_splitk % splitk != 0)
                    continue;

                const ck::index_t gemm_k_with_splitk = gemm_k_without_splitk / splitk;

                if(gemm_k_with_splitk % KPerBlock != 0)
                    continue;

                break;
            }

            // A desc
            a_grid_desc_b_m_k_ = MakeAGridDescriptor_B_M_K(a_g_n_k_wos_lengths,
                                                           a_g_n_k_wos_strides,
                                                           b_g_n_c_wis_lengths,
                                                           b_g_n_c_wis_strides,
                                                           c_g_k_c_xs_lengths,
                                                           c_g_k_c_xs_strides,
                                                           conv_filter_strides,
                                                           conv_filter_dilations,
                                                           input_left_pads,
                                                           input_right_pads,
                                                           splitk);

            // B desc
            b_grid_desc_b_n_k_ = MakeBGridDescriptor_B_N_K(a_g_n_k_wos_lengths,
                                                           a_g_n_k_wos_strides,
                                                           b_g_n_c_wis_lengths,
                                                           b_g_n_c_wis_strides,
                                                           c_g_k_c_xs_lengths,
                                                           c_g_k_c_xs_strides,
                                                           conv_filter_strides,
                                                           conv_filter_dilations,
                                                           input_left_pads,
                                                           input_right_pads,
                                                           splitk);

            block_2_ctile_map_ =
                GridwiseGemm::MakeDefaultBlock2CTileMap(c_grid_desc_m_n_, M01, N01, splitk);

            if(GridwiseGemm::CheckValidity(
                   a_grid_desc_b_m_k_, b_grid_desc_b_n_k_, c_grid_desc_m_n_, block_2_ctile_map_))
            {
                c_grid_desc_interleaved_ =
                    GridwiseGemm::MakeCGridDescriptorInterleaved12D(c_grid_desc_m_n_);
            }
        }

        void Print() const
        {
            std::cout << "A[M, K]: " << a_grid_desc_b_m_k_ << std::endl;
            std::cout << "B[N, K]: " << b_grid_desc_b_n_k_ << std::endl;
            std::cout << "C[M, N]: " << c_grid_desc_m_n_ << std::endl;
            std::cout << "CInterleaved: " << c_grid_desc_interleaved_ << std::endl;
        }

        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;

        ck::index_t num_group_;

        AGridDesc_B_M_K a_grid_desc_b_m_k_;
        BGridDesc_B_N_K b_grid_desc_b_n_k_;
        CGridDesc_M_N c_grid_desc_m_n_;
        typename GridwiseGemm::CGridDescInterleaved c_grid_desc_interleaved_;
        typename GridwiseGemm::DefaultBlock2CTileMap block_2_ctile_map_;

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

        float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {
            if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_b_m_k_,
                                            arg.b_grid_desc_b_n_k_,
                                            arg.c_grid_desc_m_n_,
                                            arg.block_2_ctile_map_))
            {
                throw std::runtime_error(
                    "wrong! GridwiseGemm_mmac_tn_mk_nk_mn_v2 has invalid setting");
            }

            const index_t grid_size =
                arg.block_2_ctile_map_.CalculateGridSize(arg.c_grid_desc_m_n_) * arg.num_group_;

            const auto K = arg.a_grid_desc_b_m_k_.GetLength(I2);

            const bool has_main_k_block_loop = GridwiseGemm::CalculateHasMainKBlockLoop(K);

            // 16 waves per CU
            constexpr index_t WaveSize      = 64;
            constexpr index_t MinWavePerCu  = 8;
            constexpr index_t WavesPerBlock = BlockSize / WaveSize;
            constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

            auto launch_kernel = [&](auto has_main_k_block_loop_) {
                constexpr bool has_main_loop = has_main_k_block_loop_.value;

                const auto kernel = kernel_grouped_conv_bwd_weight_mmac_nchw_v2<
                    GridwiseGemm,
                    ADataType,
                    BDataType,
                    CDataType,
                    AElementwiseOperation,
                    BElementwiseOperation,
                    CElementwiseOperation,
                    remove_reference_t<typename DeviceOp::AGridDesc_B_M_K>,
                    remove_reference_t<typename DeviceOp::BGridDesc_B_N_K>,
                    remove_reference_t<typename GridwiseGemm::CGridDescInterleaved>,
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
                                              arg.a_element_op_,
                                              arg.b_element_op_,
                                              arg.c_element_op_,
                                              arg.num_group_,
                                              arg.a_grid_desc_b_m_k_,
                                              arg.b_grid_desc_b_n_k_,
                                              arg.c_grid_desc_interleaved_,
                                              arg.block_2_ctile_map_,
                                              arg.compute_ptr_offset_of_batch_);
            };

            if(has_main_k_block_loop)
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
        else
        {
            // TODO: only support 1x1s1p0 conv wrw for now
            return false;
        }

        if constexpr(is_same_v<ALayout, tensor_layout::convolution::NGKHW> &&
                     is_same_v<BLayout, tensor_layout::convolution::NGCHW>)
        {
            const ck::index_t HoWo = arg.a_g_n_k_wos_lengths_[3] * arg.a_g_n_k_wos_lengths_[4];
            // vector load A/B matrix from global memory
            if(!(ABlockTransferSrcVectorDim == 2 && BBlockTransferSrcVectorDim == 2 &&
                 HoWo % ABlockTransferSrcScalarPerVector == 0 &&
                 HoWo % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }

        else
        {
            return false;
        }

        if constexpr(!is_same_v<CLayout, tensor_layout::convolution::GKCYX>)
        {
            return false;
        }

        // Gridwise GEMM size
        return GridwiseGemm::CheckValidity(arg.a_grid_desc_b_m_k_,
                                           arg.b_grid_desc_b_n_k_,
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
            str << "DeviceGroupedConvBwdWeight_mmac_nchw_v2"
                << "-"
                << BlockSize << "-"
                << MPerBlock << "-"
                << NPerBlock << "-"
                << KPerBlock << "-"
                << getConvBackwardWeightSpecializationString(ConvBackwardWeightSpecialization) << "-"
                << MwaveRepeat << "-"
                << NwaveRepeat << "-"
                << MmmacRepeat << "-"
                << NmmacRepeat << "-"
                << MmmacInterleave << "-"
                << NmmacInterleave << "-"
                << ABlockTransferSrcScalarPerVector << "-"
                << BBlockTransferSrcScalarPerVector << "-"
                << NumGemmKPrefetchStage << "-"
                << GemmKSplitFactor;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
