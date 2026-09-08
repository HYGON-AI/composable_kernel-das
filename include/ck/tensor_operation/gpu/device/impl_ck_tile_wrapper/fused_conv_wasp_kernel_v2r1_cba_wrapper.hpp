// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <iostream>
#include <sstream>
#include <type_traits>

#include "ck_tile/core.hpp"
#include "ck_tile/host.hpp"
#include "ck_tile/ops/conv.hpp"
#include "ck_tile/ops/fused_conv.hpp"
#include "ck_tile/ops/elementwise.hpp"

#include "ck/tensor_operation/gpu/device/device_grouped_conv_fwd_bias_activation.hpp"
#include "ck/tensor_operation/gpu/device/impl_ck_tile_wrapper/utils.hpp"

namespace ck {
namespace tensor_operation {
namespace device {

template <ck_tile::index_t NDimSpatial,
          typename InLayout_,
          typename WeiLayout_,
          typename OutLayout_,
          typename InDataType_,
          typename WeiDataType_,
          typename AccDataType_,
          typename OutDataType_,
          typename BiasDataType_,
          typename InElementOp_,
          typename WeiElementOp_,
          typename OutElementOp_,
          ck_tile::ConvFwdSpec ConvSpec,
          ck_tile::index_t MWGs,
          ck_tile::index_t NWGs,
          ck_tile::index_t MPerWG,
          ck_tile::index_t NPerWG,
          ck_tile::index_t KPerBlock,
          ck_tile::index_t MmmacIter,
          ck_tile::index_t NmmacIter,
          typename InWeiGmemLoadVecLens,
          typename InWeiSmemLoadStoreVecLens,
          ck_tile::index_t OutGmemStoreVecLen,
          ck_tile::index_t NumPrefetch>
struct FusedConvWaspKernelV2R1_CBA_Wrapper
    : public DeviceGroupedConvFwdBiasActivation<NDimSpatial,
                                                InLayout_,
                                                WeiLayout_,
                                                OutLayout_,
                                                InDataType_,
                                                WeiDataType_,
                                                OutDataType_,
                                                BiasDataType_,
                                                InElementOp_,
                                                WeiElementOp_,
                                                OutElementOp_>
{
    using DeviceOp = FusedConvWaspKernelV2R1_CBA_Wrapper;

    using InLayout  = typename LayoutWrapper<InLayout_>::type;
    using WeiLayout = typename LayoutWrapper<WeiLayout_>::type;
    using OutLayout = typename LayoutWrapper<OutLayout_>::type;

    using InDataType   = typename DtypeWrapper<InDataType_>::type;
    using WeiDataType  = typename DtypeWrapper<WeiDataType_>::type;
    using OutDataType  = typename DtypeWrapper<OutDataType_>::type;
    using AccDataType  = typename DtypeWrapper<AccDataType_>::type;
    using BiasDataType = typename DtypeWrapper<BiasDataType_>::type;

    using InElementOp  = typename ElemOpWrapper<InElementOp_>::type;
    using WeiElementOp = typename ElemOpWrapper<WeiElementOp_>::type;
    using OutElementOp = typename ElemOpWrapper<OutElementOp_>::type;

    static constexpr auto FuseMode = ck_tile::FusedConvModeTraits<OutElementOp>::value;

    // 4 waves per WG
    static constexpr ck_tile::index_t MWarpsPerWG = 2;
    static constexpr ck_tile::index_t NWarpsPerWG = 2;

    // tile shape
    static constexpr auto WGs      = ck_tile::sequence<MWGs, NWGs>{};
    static constexpr auto WGTile   = ck_tile::sequence<MPerWG, NPerWG, KPerBlock>{};
    static constexpr auto WGWarps  = ck_tile::sequence<MWarpsPerWG, NWarpsPerWG>{};
    static constexpr auto WarpTile = ck_tile::sequence<MmmacIter, NmmacIter, 1, 1>{};

    using TileShape = ck_tile::FusedConvWaspTileShapeV1<decltype(WGs),
                                                        decltype(WGTile),
                                                        decltype(WGWarps),
                                                        decltype(WarpTile)>;

    using TileTraits =
        ck_tile::FusedConvTileTraits<ck_tile::tuple<InLayout, WeiLayout, OutLayout>,
                                     ck_tile::tuple<InElementOp, WeiElementOp, OutElementOp>,
                                     InWeiGmemLoadVecLens,
                                     InWeiSmemLoadStoreVecLens,
                                     OutGmemStoreVecLen>;

    using Problem = ck_tile::FusedConvWaspProblemV1<
        NDimSpatial,
        ck_tile::tuple<InDataType, WeiDataType, OutDataType, AccDataType, OutDataType, OutDataType>,
        TileShape,
        TileTraits,
        NumPrefetch,
        true>;

    using Policy = ck_tile::FusedConvIgemmPipelineWaspPolicyV2R1;

    using TilePartitioner = ck_tile::ConvIgemmTilePartitioner<TileShape>;

    using WarpGemm = typename ck_tile::conv::WarpGemmMmacDispatcher<InDataType,
                                                                    WeiDataType,
                                                                    AccDataType,
                                                                    MmmacIter,
                                                                    NmmacIter,
                                                                    16,
                                                                    16,
                                                                    1,
                                                                    1,
                                                                    1,
                                                                    true>;

    using Pipeline = ck_tile::FusedConvIgemmPipelineWaspAgmemBgmemCregV2R1<Problem, Policy>;

    using Epilogue = ck_tile::FusedConvEpilogueWaspV1<Problem, WarpGemm>;

    using Kernel =
        ck_tile::FusedConvWaspKernelV2R1<TilePartitioner, Pipeline, Epilogue, ConvSpec, FuseMode>;

    using HostArgs = ck_tile::FusedConvHostArgs<NDimSpatial>;

    using KernelArgs = typename Kernel::KernelArgs;

    // launch config
    static constexpr ck_tile::index_t BlockSize =
        MWarpsPerWG * NWarpsPerWG * MWGs * NWGs * ck_tile::get_warp_size();
    static constexpr ck_tile::index_t MinBlockPerCU = 2;

    // Argument
    struct Argument : public BaseArgument
    {
        Argument(const void* p_in,
                 const void* p_wei,
                 void* p_out,
                 const void* p_bias,
                 const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_strides,
                 const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_lengths,
                 const std::array<ck::index_t, NDimSpatial + 3>& out_g_n_k_wos_strides,
                 const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                 const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                 const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                 const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                 const InElementOp_&,
                 const WeiElementOp_&,
                 const OutElementOp_&)
        {
            hargs = Kernel::MakeHostArgs(p_in,
                                         p_wei,
                                         p_out,
                                         p_bias,
                                         nullptr,
                                         in_g_n_c_wis_lengths,
                                         in_g_n_c_wis_strides,
                                         wei_g_k_c_xs_lengths,
                                         wei_g_k_c_xs_strides,
                                         out_g_n_k_wos_lengths,
                                         out_g_n_k_wos_strides,
                                         conv_filter_strides,
                                         conv_filter_dilations,
                                         input_left_pads,
                                         input_right_pads);

            kargs = Kernel::MakeKernelArgs(hargs);

            num_loop = Kernel::GetNumLoop(kargs);

            has_hot_loop = Kernel::CalculateHasMainLoop(num_loop);
        }

        HostArgs hargs;
        KernelArgs kargs;
        index_t num_loop;
        bool has_hot_loop;
    };

    // Invoker
    struct Invoker : public BaseInvoker
    {
        using Argument = DeviceOp::Argument;

        float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {

            auto launch_kernel = [&](auto has_hot_loop) {
                return ck_tile::launch_kernel(
                    {stream_config.stream_id_, stream_config.time_kernel_},
                    ck_tile::make_kernel<BlockSize, MinBlockPerCU>(
                        Kernel{},
                        arg.kargs.tile_partitioner.CalculateGridSize(),
                        BlockSize,
                        0,
                        arg.kargs,
                        has_hot_loop));
            };

            if(arg.has_hot_loop)
            {
                return launch_kernel(ck_tile::bool_constant<true>{});
            }
            else
            {
                return launch_kernel(ck_tile::bool_constant<false>{});
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
        return Kernel::IsSupportedArgument(arg.hargs, arg.kargs);
    }

    bool IsSupportedArgument(const BaseArgument* p_arg) override
    {
        return IsSupportedArgument(*dynamic_cast<const Argument*>(p_arg));
    }

    static auto MakeArgument(const void* p_in,
                             const void* p_wei,
                             void* p_out,
                             const void* p_bias,
                             const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_strides,
                             const std::array<ck::index_t, NDimSpatial + 3>& out_g_k_wos_lengths,
                             const std::array<ck::index_t, NDimSpatial + 3>& out_g_k_wos_strides,
                             const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                             const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                             const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                             const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                             const InElementOp_& in_elem_op,
                             const WeiElementOp_& wei_elem_op,
                             const OutElementOp_& out_elem_op)
    {
        return Argument(p_in,
                        p_wei,
                        p_out,
                        p_bias,
                        in_g_n_c_wis_lengths,
                        in_g_n_c_wis_strides,
                        wei_g_k_c_xs_lengths,
                        wei_g_k_c_xs_strides,
                        out_g_k_wos_lengths,
                        out_g_k_wos_strides,
                        conv_filter_strides,
                        conv_filter_dilations,
                        input_left_pads,
                        input_right_pads,
                        in_elem_op,
                        wei_elem_op,
                        out_elem_op);
    }

    static auto MakeInvoker() { return Invoker{}; }

    std::unique_ptr<BaseArgument>
    MakeArgumentPointer(const void* p_in,
                        const void* p_wei,
                        void* p_out,
                        const void* p_bias,
                        const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& in_g_n_c_wis_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& wei_g_k_c_xs_strides,
                        const std::array<ck::index_t, NDimSpatial + 3>& out_g_k_wos_lengths,
                        const std::array<ck::index_t, NDimSpatial + 3>& out_g_k_wos_strides,
                        const std::array<ck::index_t, NDimSpatial>& conv_filter_strides,
                        const std::array<ck::index_t, NDimSpatial>& conv_filter_dilations,
                        const std::array<ck::index_t, NDimSpatial>& input_left_pads,
                        const std::array<ck::index_t, NDimSpatial>& input_right_pads,
                        const InElementOp_& in_elem_op,
                        const WeiElementOp_& wei_elem_op,
                        const OutElementOp_& out_elem_op) override
    {
        return std::make_unique<Argument>(p_in,
                                          p_wei,
                                          p_out,
                                          p_bias,
                                          in_g_n_c_wis_lengths,
                                          in_g_n_c_wis_strides,
                                          wei_g_k_c_xs_lengths,
                                          wei_g_k_c_xs_strides,
                                          out_g_k_wos_lengths,
                                          out_g_k_wos_strides,
                                          conv_filter_strides,
                                          conv_filter_dilations,
                                          input_left_pads,
                                          input_right_pads,
                                          in_elem_op,
                                          wei_elem_op,
                                          out_elem_op);
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
        str << "FusedConvWaspKernelV2R1_CBA_Wrapper"
            << "-"
            << BlockSize << "-"
            << MWGs << "-"
            << NWGs << "-"
            << MPerWG << "-"
            << NPerWG << "-"
            << KPerBlock << "-"
            << ck_tile::GetConvFwdSpecString(ConvSpec) << "-"
            << MmmacIter << "-"
            << NmmacIter << "-"
            << InWeiGmemLoadVecLens::at(ck_tile::number<0>{}) << "-"
            << InWeiGmemLoadVecLens::at(ck_tile::number<1>{}) << "-"
            << InWeiSmemLoadStoreVecLens::at(ck_tile::number<0>{}) << "-"
            << InWeiSmemLoadStoreVecLens::at(ck_tile::number<1>{}) << "-"
            << OutGmemStoreVecLen << "-"
            << NumPrefetch;
        // clang-format on

        return str.str();
    }
};

} // namespace device
} // namespace tensor_operation
} // namespace ck
