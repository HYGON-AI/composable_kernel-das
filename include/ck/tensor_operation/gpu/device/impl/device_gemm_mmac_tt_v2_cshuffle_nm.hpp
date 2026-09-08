// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Info Technologies Ltd.

#pragma once

#include <iostream>
#include <sstream>

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/device_gemm.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_gemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle.hpp"
#include "ck/host_utility/device_prop.hpp"
#include "ck/host_utility/kernel_launch.hpp"
#include "ck/host_utility/io.hpp"

namespace ck {
namespace tensor_operation {
namespace device {

template <typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename CDataType,
          InMemoryDataOperationEnum CGlobalMemoryDataOperation,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          GemmSpecialization GemmSpec,
          ck::index_t BlockSize,
          index_t MPerBlock,
          index_t N0PerBlock,
          index_t N1PerBlock,
          index_t K0PerBlock,
          index_t K1PerBlock,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MwaveRepeat,
          index_t NwaveRepeat,
          index_t MmmacRepeat,
          index_t NmmacRepeat,
          index_t MmmacInterleave,
          index_t NmmacInterleave,
          typename ABlockTransferThreadClusterLengths_B_M_K,
          index_t ABlockTransferSrcVectorDim,
          index_t ABlockTransferSrcScalarPerVector,
          typename BBlockTransferThreadClusterLengths_B_N0_K0_K1_N1,
          index_t BBlockTransferSrcVectorDim,
          index_t BBlockTransferSrcScalarPerVector,
          index_t CShuffleMwaveRepeatPerShuffle,
          index_t CShuffleNwaveRepeatPerShuffle,
          typename CShuffleBlockTransferClusterLengths_N0_N1_N2_M0_M1_M2,
          index_t CShuffleBlockTransferDstScalarPerVector,
          index_t NumGemmKPrefetchStage>
struct DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle
    : public DeviceGemm<ck::tensor_layout::gemm::RowMajor,
                        ck::tensor_layout::gemm::RowMajor,
                        ck::tensor_layout::gemm::ColumnMajor,
                        ADataType,
                        BDataType,
                        CDataType,
                        AElementwiseOperation,
                        BElementwiseOperation,
                        CElementwiseOperation>
{
    static constexpr auto I0 = Number<0>{};
    static constexpr auto I1 = Number<1>{};
    static constexpr auto I2 = Number<2>{};

    static auto MakeAGridDescriptor_B_M_K(index_t M, index_t K, index_t KSplit)
    {
        const auto a_grid_desc_m_k = make_naive_tensor_descriptor_packed(make_tuple(M, K));

        const auto KSub = K / KSplit;

        return transform_tensor_descriptor(
            a_grid_desc_m_k,
            make_tuple(make_pass_through_transform(M),
                       make_unmerge_transform(make_tuple(KSplit, KSub))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<1>{}, Sequence<0, 2>{}));
    }

    static auto MakeBGridDescriptor_B_N0_K0_K1_N1(index_t N, index_t K, index_t KSplit)
    {
        const auto b_grid_desc_k_n = make_naive_tensor_descriptor_packed(make_tuple(K, N));

        const auto KSub = K / KSplit;

        const auto K0 = KSub / K1PerBlock;
        const auto N0 = N / N1PerBlock;

        return transform_tensor_descriptor(
            b_grid_desc_k_n,
            make_tuple(make_unmerge_transform(make_tuple(KSplit, K0, K1PerBlock)),
                       make_unmerge_transform(make_tuple(N0, N1PerBlock))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 2, 3>{}, Sequence<1, 4>{}));
    }

    static auto MakeCGridDescriptor_M_N(index_t M, index_t N)
    {
        const auto c_grid_desc_m_n =
            make_naive_tensor_descriptor(make_tuple(M, N), make_tuple(I1, M));

        return c_grid_desc_m_n;
    }

    using AGridDesc_B_M_K         = decltype(MakeAGridDescriptor_B_M_K(1, 1, 1));
    using BGridDesc_B_N0_K0_K1_N1 = decltype(MakeBGridDescriptor_B_N0_K0_K1_N1(1, 1, 1));
    using CGridDesc_M_N           = decltype(MakeCGridDescriptor_M_N(1, 1));

    using GridwiseGemm = GridwiseGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle<
        BlockSize,
        ADataType,
        BDataType,
        AccDataType,
        CDataType,
        CGlobalMemoryDataOperation,
        AElementwiseOperation,
        BElementwiseOperation,
        CElementwiseOperation,
        AGridDesc_B_M_K,
        BGridDesc_B_N0_K0_K1_N1,
        CGridDesc_M_N,
        MPerBlock,
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
        ABlockTransferThreadClusterLengths_B_M_K,
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
        Argument(const ADataType* p_a_grid,
                 const BDataType* p_b_grid,
                 CDataType* p_c_grid,
                 index_t M,
                 index_t N,
                 index_t K,
                 index_t M01,
                 index_t N01,
                 AElementwiseOperation a_element_op,
                 BElementwiseOperation b_element_op,
                 CElementwiseOperation c_element_op)
            : p_a_grid_{p_a_grid},
              p_b_grid_{p_b_grid},
              p_c_grid_{p_c_grid},
              a_grid_desc_b_m_k_{},
              b_grid_desc_b_n0_k0_k1_n1_{},
              c_grid_desc_m_n_{},
              cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_{},
              block_2_ctile_map_{},
              M01_{M01},
              N01_{N01},
              a_element_op_{a_element_op},
              b_element_op_{b_element_op},
              c_element_op_{c_element_op},
              KSplit_(1)
        {
            a_grid_desc_b_m_k_ =
                DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::MakeAGridDescriptor_B_M_K(
                    M, K, KSplit_);
            b_grid_desc_b_n0_k0_k1_n1_ =
                DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::MakeBGridDescriptor_B_N0_K0_K1_N1(
                    N, K, KSplit_);
            c_grid_desc_m_n_ =
                DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::MakeCGridDescriptor_M_N(M, N);

            block_2_ctile_map_ =
                GridwiseGemm::MakeDefaultBlock2CTileMap(c_grid_desc_m_n_, M01, N01, KSplit_);

            if(GridwiseGemm::CheckValidity(a_grid_desc_b_m_k_,
                                           b_grid_desc_b_n0_k0_k1_n1_,
                                           c_grid_desc_m_n_,
                                           block_2_ctile_map_))
            {
                cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_ =
                    GridwiseGemm::MakeCShuffleGridDescriptor_N0_N1_N2_M0_M1_M2(c_grid_desc_m_n_);
            }
        }

        //  private:
        const ADataType* p_a_grid_;
        const BDataType* p_b_grid_;
        CDataType* p_c_grid_;
        AGridDesc_B_M_K a_grid_desc_b_m_k_;
        BGridDesc_B_N0_K0_K1_N1 b_grid_desc_b_n0_k0_k1_n1_;
        CGridDesc_M_N c_grid_desc_m_n_;
        typename GridwiseGemm::CShuffleGridDesc_N0_N1_N2_M0_M1_M2
            cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_;
        typename GridwiseGemm::DefaultBlock2CTileMap block_2_ctile_map_;
        index_t M01_;
        index_t N01_;
        AElementwiseOperation a_element_op_;
        BElementwiseOperation b_element_op_;
        CElementwiseOperation c_element_op_;
        index_t KSplit_;
    };

    // Invoker
    struct Invoker : public BaseInvoker
    {
        using Argument = DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::Argument;

        float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {
            const index_t grid_size =
                arg.block_2_ctile_map_.CalculateGridSize(arg.c_grid_desc_m_n_);

            const auto K = arg.a_grid_desc_b_m_k_.GetLength(I2);

            float ave_time = 0;

            if(GridwiseGemm::CalculateHasMainKBlockLoop(K))
            {
                const auto kernel = kernel_gemm_mmac<
                    GridwiseGemm,
                    ADataType,
                    BDataType,
                    CDataType,
                    remove_reference_t<
                        DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::AGridDesc_B_M_K>,
                    remove_reference_t<
                        DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::BGridDesc_B_N0_K0_K1_N1>,
                    remove_reference_t<typename GridwiseGemm::CShuffleGridDesc_N0_N1_N2_M0_M1_M2>,
                    AElementwiseOperation,
                    BElementwiseOperation,
                    CElementwiseOperation,
                    remove_reference_t<typename GridwiseGemm::DefaultBlock2CTileMap>,
                    true>;

                ave_time = launch_and_time_kernel(stream_config,
                                                  kernel,
                                                  dim3(grid_size),
                                                  dim3(BlockSize),
                                                  0,
                                                  arg.p_a_grid_,
                                                  arg.p_b_grid_,
                                                  arg.p_c_grid_,
                                                  arg.a_grid_desc_b_m_k_,
                                                  arg.b_grid_desc_b_n0_k0_k1_n1_,
                                                  arg.cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_,
                                                  arg.a_element_op_,
                                                  arg.b_element_op_,
                                                  arg.c_element_op_,
                                                  arg.block_2_ctile_map_);
            }
            else
            {
                const auto kernel = kernel_gemm_mmac<
                    GridwiseGemm,
                    ADataType,
                    BDataType,
                    CDataType,
                    remove_reference_t<
                        DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::AGridDesc_B_M_K>,
                    remove_reference_t<
                        DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle::BGridDesc_B_N0_K0_K1_N1>,
                    remove_reference_t<typename GridwiseGemm::CShuffleGridDesc_N0_N1_N2_M0_M1_M2>,
                    AElementwiseOperation,
                    BElementwiseOperation,
                    CElementwiseOperation,
                    remove_reference_t<typename GridwiseGemm::DefaultBlock2CTileMap>,
                    false>;

                ave_time = launch_and_time_kernel(stream_config,
                                                  kernel,
                                                  dim3(grid_size),
                                                  dim3(BlockSize),
                                                  0,
                                                  arg.p_a_grid_,
                                                  arg.p_b_grid_,
                                                  arg.p_c_grid_,
                                                  arg.a_grid_desc_b_m_k_,
                                                  arg.b_grid_desc_b_n0_k0_k1_n1_,
                                                  arg.cshuffle_grid_desc_n0_n1_n2_m0_m1_m2_,
                                                  arg.a_element_op_,
                                                  arg.b_element_op_,
                                                  arg.c_element_op_,
                                                  arg.block_2_ctile_map_);
            }

            return ave_time;
        }

        // polymorphic
        float Run(const BaseArgument* p_arg,
                  const StreamConfig& stream_config = StreamConfig{}) override
        {
            return Run(*dynamic_cast<const Argument*>(p_arg), stream_config);
        }
    };

    static bool IsSupportedArgument(const Argument& /*arg*/) { return true; }

    // polymorphic
    bool IsSupportedArgument(const BaseArgument* p_arg) override
    {
        return IsSupportedArgument(*dynamic_cast<const Argument*>(p_arg));
    }

    static auto MakeArgument(const ADataType* p_a,
                             const BDataType* p_b,
                             CDataType* p_c,
                             index_t M,
                             index_t N,
                             index_t K,
                             index_t /* StrideA */,
                             index_t /* StrideB */,
                             index_t /* StrideC */,
                             AElementwiseOperation a_element_op,
                             BElementwiseOperation b_element_op,
                             CElementwiseOperation c_element_op)
    {
        return Argument{p_a, p_b, p_c, M, N, K, 1, 1, a_element_op, b_element_op, c_element_op};
    }

    static auto MakeInvoker() { return Invoker{}; }

    // polymorphic
    std::unique_ptr<BaseArgument> MakeArgumentPointer(const void* p_a,
                                                      const void* p_b,
                                                      void* p_c,
                                                      index_t M,
                                                      index_t N,
                                                      index_t K,
                                                      index_t /* StrideA */,
                                                      index_t /* StrideB */,
                                                      index_t /* StrideC */,
                                                      AElementwiseOperation a_element_op,
                                                      BElementwiseOperation b_element_op,
                                                      CElementwiseOperation c_element_op) override
    {
        return std::make_unique<Argument>(static_cast<const ADataType*>(p_a),
                                          static_cast<const BDataType*>(p_b),
                                          static_cast<CDataType*>(p_c),
                                          M,
                                          N,
                                          K,
                                          1,
                                          1,
                                          a_element_op,
                                          b_element_op,
                                          c_element_op);
    }

    // polymorphic
    std::unique_ptr<BaseInvoker> MakeInvokerPointer() override
    {
        return std::make_unique<Invoker>(Invoker{});
    }

    // polymorphic
    std::string GetTypeString() const override
    {
        auto str = std::stringstream();

        // clang-format off
        str << "DeviceGemm_mmac_tt_mk_n0k0k1n1_nm_v2_cshuffle"
            << "-"
            << BlockSize << "-"
            << MPerBlock << "-"
            << N0PerBlock << "-"
            << N1PerBlock << "-"
            << K0PerBlock << "-"
            << K1PerBlock << "-"
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
