// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <iostream>
#include <sstream>

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/device_grouped_conv_fwd.hpp"
#include "ck/tensor_operation/gpu/device/convolution_forward_specialization.hpp"
#include "ck/tensor_operation/operator_transform/transform_conv_fwd_to_gemm.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_v2r3.hpp"
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

template <typename GridwiseGemm,
          typename ADataType,
          typename BDataType,
          typename CDataType,
          typename AGridDesc_K0_M_K1,
          typename BGridDesc_K0_N_K1,
          typename CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2,
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
    kernel_grouped_conv_fwd_mmac(
        const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const AGridDesc_K0_M_K1 a_grid_desc_k0_m_k1,
        const BGridDesc_K0_N_K1 b_grid_desc_k0_n_k1,
        const CGridDesc_M0_N0_M1_N1_M2_M3_M4_N2 c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4,
        const AElementwiseOperation a_element_op,
        const BElementwiseOperation b_element_op,
        const CElementwiseOperation c_element_op,
        const ck::index_t group_count,
        const Block2CTileMap block_2_ctile_map,
        const ComputePtrOffsetOfBatch compute_ptr_offset_of_batch)
{
#if(!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
    defined(__gfx936__) || defined(__gfx938__))

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

    __shared__ char p_shared[GridwiseGemm::GetSharedMemoryNumberOfByte()];

    GridwiseGemm::template Run<HasMainKBlockLoop>(p_a_grid + a_batch_offset,
                                                  p_b_grid + b_batch_offset,
                                                  p_c_grid + c_batch_offset,
                                                  p_shared,
                                                  a_grid_desc_k0_m_k1,
                                                  b_grid_desc_k0_n_k1,
                                                  c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4,
                                                  a_element_op,
                                                  b_element_op,
                                                  c_element_op,
                                                  block_2_ctile_map);

#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = a_grid_desc_k0_m_k1;
    ignore = b_grid_desc_k0_n_k1;
    ignore = c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4;
    ignore = a_element_op;
    ignore = b_element_op;
    ignore = c_element_op;
    ignore = group_count;
    ignore = block_2_ctile_map;
    ignore = compute_ptr_offset_of_batch;
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
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          ConvolutionForwardSpecialization ConvForwardSpecialization,
          ck::index_t BlockSize,
          ck::index_t MPerBlock,
          ck::index_t NPerBlock,
          ck::index_t K0PerBlock,
          ck::index_t K1,
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
          ck::index_t NumGemmKPrefetchStage = 1,
          LoopScheduler LoopSched           = make_default_loop_scheduler()>
struct DeviceGroupedConvFwd_Mmac : public DeviceGroupedConvFwd<NDimSpatial,
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
    using DeviceOp = DeviceGroupedConvFwd_Mmac;

    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};

    static constexpr auto conv_to_gemm_transformer =
        TransformConvFwdToGemm<NDimSpatial, ConvForwardSpecialization>{};

    static constexpr auto matrix_padder =
        MatrixPadder<GemmSpecialization::MNKPadding, ck::index_t, ck::index_t, ck::index_t>{
            MPerBlock, NPerBlock, K0PerBlock* K1};

    template <typename ALayout_>
    static auto
    MakeAGridDescriptor_K0_M_K1(const std::array<ck::index_t, NDimSpatial + 3>& a_g_n_c_wis_lengths,
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
            conv_to_gemm_transformer.template MakeADescriptor_M_K<ALayout>(a_g_n_c_wis_lengths,
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

        const auto M  = in_gemmm_gemmk_desc.GetLength(I0);
        const auto K  = in_gemmm_gemmk_desc.GetLength(I1);
        const auto K0 = K / K1;

        return transform_tensor_descriptor(
            in_gemmm_gemmk_desc,
            make_tuple(make_unmerge_transform(make_tuple(K0, K1)), make_pass_through_transform(M)),
            make_tuple(Sequence<1>{}, Sequence<0>{}),
            make_tuple(Sequence<0, 2>{}, Sequence<1>{}));
    }

    template <typename BLayout_>
    static auto
    MakeBGridDescriptor_K0_N_K1(const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_lengths,
                                const std::array<ck::index_t, NDimSpatial + 3>& b_g_k_c_xs_strides)
    {
        const auto wei_gemmnraw_gemmkraw_desc =
            conv_to_gemm_transformer.template MakeBDescriptor_N_K<BLayout>(b_g_k_c_xs_lengths,
                                                                           b_g_k_c_xs_strides);

        const auto wei_gemmn_gemmk_desc =
            matrix_padder.PadBDescriptor_N_K(wei_gemmnraw_gemmkraw_desc);

        const auto N  = wei_gemmn_gemmk_desc.GetLength(I0);
        const auto K  = wei_gemmn_gemmk_desc.GetLength(I1);
        const auto K0 = K / K1;

        return transform_tensor_descriptor(
            wei_gemmn_gemmk_desc,
            make_tuple(make_unmerge_transform(make_tuple(K0, K1)), make_pass_through_transform(N)),
            make_tuple(Sequence<1>{}, Sequence<0>{}),
            make_tuple(Sequence<0, 2>{}, Sequence<1>{}));
    }

    template <typename CLayout_>
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

    // desc for problem definition
    using AGridDesc_K0_M_K1 = remove_cvref_t<decltype(MakeAGridDescriptor_K0_M_K1<ALayout>(
        {}, {}, {}, {}, {}, {}, {}, {}, {}, {}))>;
    using BGridDesc_K0_N_K1 =
        remove_cvref_t<decltype(MakeBGridDescriptor_K0_N_K1<BLayout>({}, {}))>;
    using CGridDesc_M_N = remove_cvref_t<decltype(MakeCGridDescriptor_M_N<CLayout>({}, {}))>;

    // GridwiseGemm
    using GridwiseGemm = GridwiseGemm_k0mk1_k0nk1_mn_mmac_v2r3<
        BlockSize,
        ADataType,
        BDataType,
        AccDataType,
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
        K0PerBlock,
        MPerMmac,
        NPerMmac,
        K1,
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
        Sequence<2, 3, 0, 1, 7, 5, 4, 6>, // CThreadTransferSrcDstAccessOrder,
        7,                                // CThreadTransferSrcDstVectorDim,
        1,
        NumGemmKPrefetchStage,
        LoopSched>;

    // Argument
    struct Argument : public BaseArgument
    {

        Argument(const void* p_a,
                 const void* p_b,
                 void* p_c,
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
              num_group_(a_g_n_c_wis_lengths[0]),
              a_grid_desc_k0_m_k1_(MakeAGridDescriptor_K0_M_K1<ALayout>(a_g_n_c_wis_lengths,
                                                                        a_g_n_c_wis_strides,
                                                                        b_g_k_c_xs_lengths,
                                                                        b_g_k_c_xs_strides,
                                                                        c_g_n_k_wos_lengths,
                                                                        c_g_n_k_wos_strides,
                                                                        conv_filter_strides,
                                                                        conv_filter_dilations,
                                                                        input_left_pads,
                                                                        input_right_pads)),
              b_grid_desc_k0_n_k1_(
                  MakeBGridDescriptor_K0_N_K1<BLayout>(b_g_k_c_xs_lengths, b_g_k_c_xs_strides)),
              c_grid_desc_m_n_(
                  MakeCGridDescriptor_M_N<CLayout>(c_g_n_k_wos_lengths, c_g_n_k_wos_strides)),
              c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4_(),
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
            compute_ptr_offset_of_batch_.BatchStrideA_ = a_g_n_c_wis_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideB_ = b_g_k_c_xs_strides[0];
            compute_ptr_offset_of_batch_.BatchStrideC_ = c_g_n_k_wos_strides[0];

            block_2_ctile_map_ =
                GridwiseGemm::MakeDefaultBlock2CTileMap(c_grid_desc_m_n_, M01, N01);

            if(GridwiseGemm::CheckValidity(a_grid_desc_k0_m_k1_,
                                           b_grid_desc_k0_n_k1_,
                                           c_grid_desc_m_n_,
                                           block_2_ctile_map_))
            {
                c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4_ =
                    GridwiseGemm::MakeCGridDescriptor_M0_N0_M1_N1_M2_N2_N3_N4(c_grid_desc_m_n_);
            }
        }

        void Print() const
        {
            std::cout << "A[K0, M, K1]: " << a_grid_desc_k0_m_k1_ << std::endl;
            std::cout << "B[K0, N, K1]: " << b_grid_desc_k0_n_k1_ << std::endl;
            std::cout << "C[M, N]: " << c_grid_desc_m_n_ << std::endl;
        }

        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;

        ck::index_t num_group_;
        AGridDesc_K0_M_K1 a_grid_desc_k0_m_k1_;
        BGridDesc_K0_N_K1 b_grid_desc_k0_n_k1_;
        CGridDesc_M_N c_grid_desc_m_n_;
        typename GridwiseGemm::CGridDesc_M0_N0_M1_N1_M2_N2_N3_N4
            c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4_;
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

            if(!GridwiseGemm::CheckValidity(arg.a_grid_desc_k0_m_k1_,
                                            arg.b_grid_desc_k0_n_k1_,
                                            arg.c_grid_desc_m_n_,
                                            arg.block_2_ctile_map_))
            {
                throw std::runtime_error(
                    "wrong! GridwiseGemm_k0mk1_k0nk1_mn_mmac_v2r3 has invalid setting");
            }

            const ck::index_t grid_size =
                arg.block_2_ctile_map_.CalculateGridSize(arg.c_grid_desc_m_n_) * arg.num_group_;

            const auto K =
                arg.a_grid_desc_k0_m_k1_.GetLength(I0) * arg.a_grid_desc_k0_m_k1_.GetLength(I2);

            const bool has_main_k_block_loop = GridwiseGemm::CalculateHasMainKBlockLoop(K);

            // 16 waves per CU
            constexpr index_t WaveSize      = 64;
            constexpr index_t MinWavePerCu  = 8;
            constexpr index_t WavesPerBlock = BlockSize / WaveSize;
            constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

            auto launch_kernel = [&](auto has_main_k_block_loop_) {
                constexpr bool has_main_loop = has_main_k_block_loop_.value;

                const auto kernel = kernel_grouped_conv_fwd_mmac<
                    GridwiseGemm,
                    ADataType,
                    BDataType,
                    CDataType,
                    remove_reference_t<DeviceOp::AGridDesc_K0_M_K1>,
                    remove_reference_t<DeviceOp::BGridDesc_K0_N_K1>,
                    remove_reference_t<typename GridwiseGemm::CGridDesc_M0_N0_M1_N1_M2_N2_N3_N4>,
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
                                              arg.a_grid_desc_k0_m_k1_,
                                              arg.b_grid_desc_k0_n_k1_,
                                              arg.c_grid_desc_m0_n0_m1_n1_m2_n2_n3_n4_,
                                              arg.a_element_op_,
                                              arg.b_element_op_,
                                              arg.c_element_op_,
                                              arg.num_group_,
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
        namespace ctc = tensor_layout::convolution;

        // device check
        static const auto hcu_target_enum = ck::get_hcu_target_enum();

        if(hcu_target_enum < HCUTargetEnum::HCU_TARGET_GFX928)
        {
            return false;
        }

        // check ConvolutionForwardSpecialization
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
            // check if it's 1x1 conv
            for(ck::index_t i = 0; i < NDimSpatial; ++i)
            {
                const ck::index_t X        = arg.b_g_k_c_xs_lengths_[i + 3];
                const ck::index_t LeftPad  = arg.input_left_pads_[i];
                const ck::index_t RightPad = arg.input_right_pads_[i];

                if(!(X == 1 && LeftPad == 0 && RightPad == 0))
                {
                    return false;
                }
            }
        }

        // GemmA (activation) access check
        if constexpr(is_same_v<ALayout, ctc::NHWGC> || is_same_v<ALayout, ctc::GNHWC>)
        {
            const ck::index_t C = arg.a_g_n_c_wis_lengths_[2];

            if(!(ABlockTransferSrcVectorDim == 2 && C % ABlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        else if constexpr(is_same_v<ALayout, ctc::NGCHW> || is_same_v<ALayout, ctc::GNCHW>)
        {
            // for 1x1 stride1 conv, there's chance to do vector load
            if constexpr(ConvForwardSpecialization ==
                         ConvolutionForwardSpecialization::Filter1x1Stride1Pad0)
            {
                const ck::index_t HoWo = arg.c_g_n_k_wos_lengths_[3] * arg.c_g_n_k_wos_lengths_[4];

                if(!(ABlockTransferSrcVectorDim == 1 &&
                     HoWo % ABlockTransferSrcScalarPerVector == 0))
                {
                    return false;
                }
            }
            else
            {
                if constexpr(ABlockTransferSrcScalarPerVector != 1)
                {
                    return false;
                }
            }
        }
        //add NGCHWcBase
        else if constexpr(std::is_base_of<ctc::NGCHWcBase, ALayout>::value)
        {
            if constexpr(ABlockTransferSrcVectorDim != 2 ||
                         (ALayout::x) % ABlockTransferSrcScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(is_same_v<ALayout, ctc::NGCHWc32>)
        {
            if constexpr(ABlockTransferSrcVectorDim != 2 ||
                         32 % ABlockTransferSrcScalarPerVector != 0)
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
        else if constexpr(is_same_v<BLayout, ctc::GKCYX>)
        {
            const ck::index_t CRS = arg.b_g_k_c_xs_lengths_[2] * arg.b_g_k_c_xs_lengths_[3] *
                                    arg.b_g_k_c_xs_lengths_[4];

            if(!(BBlockTransferSrcVectorDim == 2 && CRS % BBlockTransferSrcScalarPerVector == 0))
            {
                return false;
            }
        }
        //add GKCYXcBase
        else if constexpr(std::is_base_of<ctc::GKCYXcBase, BLayout>::value)
        {
            if constexpr(BBlockTransferSrcVectorDim != 2 ||
                         (BLayout::x) % BBlockTransferSrcScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(is_same_v<BLayout, ctc::GKCYXc32>)
        {
            if constexpr((BBlockTransferSrcVectorDim != 2) ||
                         (32 % BBlockTransferSrcScalarPerVector != 0))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // mmac-based conv has no vector store without c shuffle

        // Gridwise GEMM size
        return GridwiseGemm::CheckValidity(arg.a_grid_desc_k0_m_k1_,
                                           arg.b_grid_desc_k0_n_k1_,
                                           arg.c_grid_desc_m_n_,
                                           arg.block_2_ctile_map_);
    }

    bool IsSupportedArgument(const BaseArgument* p_arg) override
    {
        return IsSupportedArgument(*dynamic_cast<const Argument*>(p_arg));
    }

    static auto MakeArgument(const void* p_a,
                             const void* p_b,
                             void* p_c,
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
        str << "DeviceGroupedConvFwd_Mmac"
            << "-"
            << BlockSize << "-"
            << MPerBlock << "-"
            << NPerBlock << "-"
            << K0PerBlock << "-"
            << getConvForwardSpecializationString(ConvForwardSpecialization) << "-"
            << K1 << "-"
            << MPerMmac << "-"
            << NPerMmac << "-"
            << MMmacPerWave << "-"
            << NMmacPerWave << "-"
            << ABlockTransferSrcScalarPerVector << "-"
            << ABlockTransferDstScalarPerVector_K1 << "-"
            << BBlockTransferSrcScalarPerVector << "-"
            << BBlockTransferDstScalarPerVector_K1 << "-"
            << NumGemmKPrefetchStage;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
