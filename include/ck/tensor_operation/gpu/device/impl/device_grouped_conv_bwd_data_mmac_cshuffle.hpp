// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <iostream>
#include <sstream>
#include <vector>

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/device_grouped_conv_bwd_data.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_data_specialization.hpp"
#include "ck/tensor_operation/operator_transform/transform_conv_bwd_data_to_gemm_v1.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_v3r1.hpp"
#include "ck/host_utility/device_prop.hpp"
#include "ck/host_utility/kernel_launch.hpp"
#include "ck/host_utility/io.hpp"

namespace ck {
namespace tensor_operation {
namespace device {

struct ComputePtrOffsetOfStridedBatch
{
    ComputePtrOffsetOfStridedBatch() = default;

    ComputePtrOffsetOfStridedBatch(ck::index_t BatchStrideA,
                                   ck::index_t BatchStrideB,
                                   ck::index_t BatchStrideC)
        : BatchStrideA_(BatchStrideA), BatchStrideB_(BatchStrideB), BatchStrideC_(BatchStrideC)
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

    ck::index_t BatchStrideA_;
    ck::index_t BatchStrideB_;
    ck::index_t BatchStrideC_;
};
template <
    typename GridwiseGemm,
    typename ADataType,
    typename BDataType,
    typename CDataType,
    typename AGridDesc_AK0_M_AK1,
    typename BGridDesc_BK0_N_BK1,
    typename CGridDescriptor_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac,
    typename AElementwiseOperation,
    typename BElementwiseOperation,
    typename CElementwiseOperation,
    typename Block2CTileMap,
    typename ComputePtrOffsetOfBatch,
    bool HasMainK0BlockLoop,
    ck::index_t MaxThreadPerBlock = CK_MAX_THREAD_PER_BLOCK,
    ck::index_t MinBlockPerCU     = CK_MIN_BLOCK_PER_CU>
__global__ void
#if CK_USE_LAUNCH_BOUNDS
__launch_bounds__(MaxThreadPerBlock, MinBlockPerCU)
#endif
    kernel_grouped_conv_bwd_data_mmac_cshuffle(
        const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const AGridDesc_AK0_M_AK1 a_grid_desc_ak0_m_ak1,
        const BGridDesc_BK0_N_BK1 b_grid_desc_bk0_n_bk1,
        const CGridDescriptor_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac
            c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac,
        const AElementwiseOperation a_element_op,
        const BElementwiseOperation b_element_op,
        const CElementwiseOperation c_element_op,
        const ck::index_t group_count,
        const Block2CTileMap block_2_ctile_map,
        const ComputePtrOffsetOfBatch compute_ptr_offset_of_batch)
{
#if (!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
     defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__))
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

    GridwiseGemm::template Run<HasMainK0BlockLoop>(
        p_a_grid + a_batch_offset,
        p_b_grid + b_batch_offset,
        p_c_grid + c_batch_offset,
        p_shared,
        a_grid_desc_ak0_m_ak1,
        b_grid_desc_bk0_n_bk1,
        c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac,
        a_element_op,
        b_element_op,
        c_element_op,
        block_2_ctile_map);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = a_grid_desc_ak0_m_ak1;
    ignore = b_grid_desc_bk0_n_bk1;
    ignore = c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac;
    ignore = a_element_op;
    ignore = b_element_op;
    ignore = c_element_op;
    ignore = group_count;
    ignore = block_2_ctile_map;
    ignore = compute_ptr_offset_of_batch;
#endif // end of if (defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || defined(__gfx936__) ||
       // defined(__gfx938__))
}

template <
    ck::index_t NDimSpatial,
    typename ALayout,
    typename BLayout,
    typename CLayout,
    typename ADataType,
    typename BDataType,
    typename AccDataType,
    typename CShuffleDataType,
    typename CDataType,
    typename AElementwiseOperation,
    typename BElementwiseOperation,
    typename CElementwiseOperation,
    ConvolutionBackwardDataSpecialization ConvBwdDataSpecialization,
    ck::index_t BlockSize,
    ck::index_t MPerBlock,
    ck::index_t NPerBlock,
    ck::index_t KPerBlock,
    ck::index_t AK1,
    ck::index_t BK1,
    ck::index_t MPerMmac,
    ck::index_t NPerMmac,
    ck::index_t MMmacPerWave,
    ck::index_t NMmacPerWave,
    typename ABlockTransferThreadClusterLengths_K0_M_K1,
    typename ABlockTransferThreadClusterArrangeOrder,
    typename ABlockTransferSrcAccessOrder,
    ck::index_t ABlockTransferSrcVectorDim,
    ck::index_t ABlockTransferSrcScalarPerVector,
    ck::index_t ABlockTransferDstScalarPerVector_K1,
    bool ABlockLdsAddExtraM,
    typename BBlockTransferThreadClusterLengths_K0_N_K1,
    typename BBlockTransferThreadClusterArrangeOrder,
    typename BBlockTransferSrcAccessOrder,
    ck::index_t BBlockTransferSrcVectorDim,
    ck::index_t BBlockTransferSrcScalarPerVector,
    ck::index_t BBlockTransferDstScalarPerVector_K1,
    bool BBlockLdsAddExtraN,
    ck::index_t CShuffleMMmacPerWavePerShuffle,
    ck::index_t CShuffleNMmacPerWavePerShuffle,
    typename CBlockTransferClusterLengths_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac,
    ck::index_t CBlockTransferScalarPerVector_NWaveNPerMmac,
    ck::index_t NumGemmKPrefetchStage = 1,
    LoopScheduler LoopSched           = make_default_loop_scheduler(),
    PipelineVersion PipelineVer       = PipelineVersion::v1>
struct DeviceGroupedConvBwdData_Mmac_CShuffle
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
    using DeviceOp = DeviceGroupedConvBwdData_Mmac_CShuffle;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};

    static constexpr auto conv_to_gemm_transformer =
        TransformConvBwdDataToGemm_v1<NDimSpatial,
                                      ConvBwdDataSpecialization,
                                      AK1,
                                      BK1,
                                      MPerBlock,
                                      NPerBlock,
                                      true,
                                      true>{};

    template <typename ALayout_>
    static auto MakeAGridDescriptor_K0_M_K1(
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
        return conv_to_gemm_transformer.template MakeADescriptor_AK0_M_AK1<ALayout_>(
            out_g_n_k_wos_lengths,
            out_g_n_k_wos_strides,
            wei_g_k_c_xs_lengths,
            wei_g_k_c_xs_strides,
            in_g_n_c_wis_lengths,
            in_g_n_c_wis_strides,
            conv_filter_strides,
            conv_filter_dilations,
            input_left_pads,
            input_right_pads,
            tildes);
    }

    template <typename BLayout_>
    static auto MakeBGridDescriptor_K0_N_K1(
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
        return conv_to_gemm_transformer.template MakeBDescriptor_BK0_N_BK1<BLayout_>(
            out_g_n_k_wos_lengths,
            out_g_n_k_wos_strides,
            wei_g_k_c_xs_lengths,
            wei_g_k_c_xs_strides,
            in_g_n_c_wis_lengths,
            in_g_n_c_wis_strides,
            conv_filter_strides,
            conv_filter_dilations,
            input_left_pads,
            input_right_pads,
            tildes);
    }

    template <typename CLayout_>
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
        return conv_to_gemm_transformer.template MakeCDescriptor_M_N<CLayout_>(
            out_g_n_k_wos_lengths,
            out_g_n_k_wos_strides,
            wei_g_k_c_xs_lengths,
            wei_g_k_c_xs_strides,
            in_g_n_c_wis_lengths,
            in_g_n_c_wis_strides,
            conv_filter_strides,
            conv_filter_dilations,
            input_left_pads,
            input_right_pads,
            tildes);
    }

    using AGridDesc_K0_M_K1 = remove_cvref_t<decltype(MakeAGridDescriptor_K0_M_K1<ALayout>(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    using BGridDesc_K0_N_K1 = remove_cvref_t<decltype(MakeBGridDescriptor_K0_N_K1<BLayout>(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    ;
    using CGridDesc_M_N = remove_cvref_t<decltype(MakeCGridDescriptor_M_N<CLayout>(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    ;

    // GridwiseGemm
    using GridwiseGemm = GridwiseGemm_k0mk1_k0nk1_mn_mmac_v3r1<
        BlockSize,
        ADataType,
        BDataType,
        AccDataType,
        CShuffleDataType,
        CDataType,
        InMemoryDataOperationEnum::Set,
        AGridDesc_K0_M_K1,
        BGridDesc_K0_N_K1,
        CGridDesc_M_N,
        AElementwiseOperation,
        BElementwiseOperation,
        CElementwiseOperation,
        MPerBlock,
        NPerBlock,
        KPerBlock,
        AK1,
        BK1,
        MPerMmac,
        NPerMmac,
        MMmacPerWave,
        NMmacPerWave,
        ABlockTransferThreadClusterLengths_K0_M_K1,
        ABlockTransferThreadClusterArrangeOrder,
        ABlockTransferSrcAccessOrder,
        ABlockTransferSrcVectorDim,
        ABlockTransferSrcScalarPerVector,
        ABlockTransferDstScalarPerVector_K1,
        false, // AThreadTransferSrcResetCoordinateAfterRun,
        ABlockLdsAddExtraM,
        BBlockTransferThreadClusterLengths_K0_N_K1,
        BBlockTransferThreadClusterArrangeOrder,
        BBlockTransferSrcAccessOrder,
        BBlockTransferSrcVectorDim,
        BBlockTransferSrcScalarPerVector,
        BBlockTransferDstScalarPerVector_K1,
        false, // BThreadTransferSrcResetCoordinateAfterRun,
        BBlockLdsAddExtraN,
        CShuffleMMmacPerWavePerShuffle,
        CShuffleNMmacPerWavePerShuffle,
        CBlockTransferClusterLengths_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac,
        CBlockTransferScalarPerVector_NWaveNPerMmac,
        NumGemmKPrefetchStage,
        LoopSched,
        PipelineVer>;

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
              a_grid_desc_k0_m_k1_container_(),
              b_grid_desc_k0_n_k1_container_(),
              c_grid_desc_m_n_container_(),
              c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac_container_(),
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
                    const auto a_grid_desc_ak0_m_ak1 =
                        MakeAGridDescriptor_K0_M_K1<ALayout>(a_g_n_k_wos_lengths,
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
                    const auto b_grid_desc_bk0_n_bk1 =
                        MakeBGridDescriptor_K0_N_K1<BLayout>(a_g_n_k_wos_lengths,
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
                    const auto c_grid_desc_m_n =
                        MakeCGridDescriptor_M_N<CLayout>(a_g_n_k_wos_lengths,
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

                    a_grid_desc_k0_m_k1_container_.push_back(a_grid_desc_ak0_m_ak1);
                    b_grid_desc_k0_n_k1_container_.push_back(b_grid_desc_bk0_n_bk1);
                    c_grid_desc_m_n_container_.push_back(c_grid_desc_m_n);

                    auto block_2_ctile_map =
                        GridwiseGemm::MakeDefaultBlock2CTileMap(c_grid_desc_m_n, M01, N01);
                    block_2_ctile_map_container_.push_back(block_2_ctile_map);

                    if(GridwiseGemm::CheckValidity(a_grid_desc_ak0_m_ak1,
                                                   b_grid_desc_bk0_n_bk1,
                                                   c_grid_desc_m_n,
                                                   block_2_ctile_map))
                    {
                        c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac_container_
                            .push_back(
                                GridwiseGemm::
                                    MakeCGridDescriptor_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac(
                                        c_grid_desc_m_n));
                    }
                }
            }
        }

        void Print() const
        {
            for(ck::index_t i = 0; i < num_gemm_; ++i)
            {
                const auto a_grid_desc_k0_m_k1 = a_grid_desc_k0_m_k1_container_[i];
                const auto b_grid_desc_k0_n_k1 = b_grid_desc_k0_n_k1_container_[i];
                const auto c_grid_desc_m_n     = c_grid_desc_m_n_container_[i];

                std::cout << "Gemm: " << i << std::endl;
                std::cout << "A[K0, M, K1]: " << a_grid_desc_k0_m_k1 << std::endl;
                std::cout << "B[K0, N, K1]: " << b_grid_desc_k0_n_k1 << std::endl;
                std::cout << "C[M, N]: " << c_grid_desc_m_n << std::endl;
            }
        }

        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;

        ck::index_t num_group_;
        ck::index_t num_gemm_;
        std::vector<AGridDesc_K0_M_K1> a_grid_desc_k0_m_k1_container_;
        std::vector<BGridDesc_K0_N_K1> b_grid_desc_k0_n_k1_container_;
        std::vector<CGridDesc_M_N> c_grid_desc_m_n_container_;
        std::vector<
            typename GridwiseGemm::
                CGridDescriptor_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac>
            c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac_container_;
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

            float ave_time = 0;

            for(ck::index_t i = 0; i < arg.num_gemm_; ++i)
            {
                if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_k0_m_k1_container_[i],
                                                arg.b_grid_desc_k0_n_k1_container_[i],
                                                arg.c_grid_desc_m_n_container_[i],
                                                arg.block_2_ctile_map_container_[i]))
                {
                    throw std::runtime_error(
                        "wrong! GridwiseGemm_k0mk1_k0nk1_mn_mmac_v3r1 has invalid setting");
                }

                const ck::index_t grid_size = arg.block_2_ctile_map_container_[i].CalculateGridSize(
                                                  arg.c_grid_desc_m_n_container_[i]) *
                                              arg.num_group_;

                const auto K = arg.a_grid_desc_k0_m_k1_container_[i].GetLength(I0) *
                               arg.a_grid_desc_k0_m_k1_container_[i].GetLength(I2);

                const bool has_main_k_block_loop = GridwiseGemm::CalculateHasMainKBlockLoop(K);

                // 16 waves per CU
                constexpr index_t WaveSize      = 64;
                constexpr index_t MinWavePerCu  = 8;
                constexpr index_t WavesPerBlock = BlockSize / WaveSize;
                constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

                auto launch_kernel = [&](auto has_main_k_block_loop_) {
                    constexpr bool has_main_loop = has_main_k_block_loop_.value;

                    const auto kernel = kernel_grouped_conv_bwd_data_mmac_cshuffle<
                        GridwiseGemm,
                        ADataType,
                        BDataType,
                        CDataType,
                        remove_reference_t<DeviceOp::AGridDesc_K0_M_K1>,
                        remove_reference_t<DeviceOp::BGridDesc_K0_N_K1>,
                        remove_reference_t<
                            typename GridwiseGemm::
                                CGridDescriptor_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac>,
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
                        arg.a_grid_desc_k0_m_k1_container_[i],
                        arg.b_grid_desc_k0_n_k1_container_[i],
                        arg.c_grid_desc_mblock_mmmacperwave_mwavempermmac_nblock_nmmacperwave_nwavenpermmac_container_
                            [i],
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

        const ck::index_t ConvK = arg.b_g_k_c_xs_lengths_[1];
        const ck::index_t ConvC = arg.b_g_k_c_xs_lengths_[2];

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

        // Gemm A (doutput)
        if constexpr(is_same_v<ALayout, ctc::GNHWK> || is_same_v<ALayout, ctc::NHWGK>)
        {
            // vector load along gemm k1 (ConvK)
            if(!(ABlockTransferSrcVectorDim == 2 && ConvK % ABlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else if constexpr(is_same_v<ALayout, ctc::GNKHW> || is_same_v<ALayout, ctc::NGKHW>)
        {
            // TODO: any vector load condition?
            if(ABlockTransferSrcScalarPerVector != 1)
            {
                return false;
            }
        }
        else if constexpr(is_same_v<ALayout, ctc::NGKHWk32>)
        {
            // vector load along gemm k1 (ConvK)
            if constexpr(!(ABlockTransferSrcVectorDim == 2 &&
                           32 % ABlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // Gemm B (weight)
        if constexpr(is_same_v<BLayout, ctc::GKYXC>)
        {
            // vector load along gemm n (ConvC)
            if(!(BBlockTransferSrcVectorDim == 1 && ConvC % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else if constexpr(is_same_v<BLayout, ctc::GKCYX>)
        {
            if constexpr(ConvBwdDataSpecialization ==
                         ConvolutionBackwardDataSpecialization::Filter1x1Stride1Pad0)
            {
                // vector load along gemm n (ConvC)
                if(!(BBlockTransferSrcVectorDim == 1 &&
                     ConvC % BBlockTransferSrcScalarPerVector == 0))
                {
                    return false;
                }
            }
            else
            {
                if(BBlockTransferSrcScalarPerVector != 1)
                {
                    return false;
                }
            }
        }
        else if constexpr(is_same_v<BLayout, ctc::GKCYXc32>)
        {
            // vector load along gemm n (ConvC)
            if constexpr(!(BBlockTransferSrcVectorDim == 1 &&
                           32 % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // Gemm C (dinput)
        if constexpr(is_same_v<CLayout, ctc::NHWGC> || is_same_v<CLayout, ctc::GNHWC>)
        {

            // vector store along gemm n (ConvC)
            if(!(ConvC % CBlockTransferScalarPerVector_NWaveNPerMmac == 0))
            {
                return false;
            }
        }
        else if constexpr(is_same_v<CLayout, ctc::NGCHW> || is_same_v<CLayout, ctc::GNCHW>)
        {
            if(CBlockTransferScalarPerVector_NWaveNPerMmac != 1)
            {
                return false;
            }
        }
        else if constexpr(is_same_v<CLayout, ctc::NGCHWc32>)
        {
            // vector store along gemm n (ConvC)
            if constexpr(!(32 % CBlockTransferScalarPerVector_NWaveNPerMmac == 0))
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
            if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_k0_m_k1_container_[i],
                                            arg.b_grid_desc_k0_n_k1_container_[i],
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

        // WARNING: miopen can't get complement type string with comma, never use it!!
        // clang-format off
        str << "DeviceGroupedConvBwdData_Mmac_CShuffle"
            << "-"
            << BlockSize << "-"
            << MPerBlock << "-"
            << NPerBlock << "-"
            << KPerBlock << "-"
            << getConvBackwardDataSpecializationString(ConvBwdDataSpecialization) << "-"
            << AK1 << "-"
            << BK1 << "-"
            << MPerMmac << "-"
            << NPerMmac << "-"
            << MMmacPerWave << "-"
            << NMmacPerWave << "-"
            << ABlockTransferSrcScalarPerVector << "-"
            << ABlockTransferDstScalarPerVector_K1 << "-"
            << BBlockTransferSrcScalarPerVector << "-"
            << BBlockTransferDstScalarPerVector_K1 << "-"
            << CShuffleMMmacPerWavePerShuffle << "-"
            << CShuffleNMmacPerWavePerShuffle << "-"
            << CBlockTransferScalarPerVector_NWaveNPerMmac << "-"
            << NumGemmKPrefetchStage;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
