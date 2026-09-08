// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <array>
#include <iostream>
#include <memory>
#include <utility>

#include "ck/utility/data_type.hpp"
#include "ck/utility/math.hpp"
#include "ck/utility/sequence.hpp"
#include "ck/tensor_operation/gpu/device/device_base.hpp"
#include "ck/tensor_operation/gpu/device/device_layout_transform.hpp"
#include "ck/tensor_operation/gpu/device/layout_transform_specialization.hpp"
#include "ck/tensor_operation/gpu/device/matrix_padder.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/grid/gridwise_batched_transpose.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"

#include "ck/host_utility/io.hpp"
#include "ck/host_utility/kernel_launch.hpp"

namespace ck {
namespace tensor_operation {
namespace device {

// swap H/W dimension
template <typename InDataType,
          typename OutDataType,
          typename InLayout,
          typename OutLayout,
          ck::index_t BlockSize,
          ck::index_t NPerBlock,
          ck::index_t HPerBlock,
          ck::index_t WPerBlock,
          typename InBlockTransferThreadClusterLengths_N_H_W,
          typename OutBlockTransferThreadClusterLengths_N_W_H,
          ck::index_t SrcScalarPerVector,
          ck::index_t DstScalarPerVector,
          bool AddLdsExtraH>
struct DeviceLayoutTransformImpl
    : DeviceLayoutTransform<5, InDataType, OutDataType, InLayout, OutLayout>
{
    using Lengths =
        typename DeviceLayoutTransform<5, InDataType, OutDataType, InLayout, OutLayout>::Lengths;

    static constexpr auto TransType = LayoutTransformTrait<InLayout, OutLayout>::value;

    static_assert(TransType != LayoutTransformSpecialization::UNK);

    static auto MakeGridDesc_N_GC_HW(const Lengths& g_n_c_wis_lengths)
    {
        const ck::index_t N = g_n_c_wis_lengths[1];
        const ck::index_t G = g_n_c_wis_lengths[0];
        const ck::index_t C = g_n_c_wis_lengths[2];
        const ck::index_t H = g_n_c_wis_lengths[3];
        const ck::index_t W = g_n_c_wis_lengths[4];

        const auto GC = G * C;
        const auto GCTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC ? HPerBlock : WPerBlock;
        const auto GCPad = math::integer_divide_ceil(GC, GCTile) * GCTile;

        const auto HW = H * W;
        const auto HWTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC ? WPerBlock : HPerBlock;
        const auto HWPad = math::integer_divide_ceil(HW, HWTile) * HWTile;

        const auto in_n_gc_hw_desc = make_naive_tensor_descriptor_packed(make_tuple(N, GC, HW));

        return transform_tensor_descriptor(in_n_gc_hw_desc,
                                           make_tuple(make_pass_through_transform(N),
                                                      make_right_pad_transform(GC, GCPad - GC),
                                                      make_right_pad_transform(HW, HWPad - HW)),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));
    }

    static auto MakeGridDesc_N_HW_GC(const Lengths& g_n_c_wis_lengths)
    {
        const ck::index_t N = g_n_c_wis_lengths[1];
        const ck::index_t H = g_n_c_wis_lengths[3];
        const ck::index_t W = g_n_c_wis_lengths[4];
        const ck::index_t G = g_n_c_wis_lengths[0];
        const ck::index_t C = g_n_c_wis_lengths[2];

        const auto HW = H * W;
        const auto HWTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC ? WPerBlock : HPerBlock;
        const auto HWPad = math::integer_divide_ceil(HW, HWTile) * HWTile;

        const auto GC = G * C;
        const auto GCTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC ? HPerBlock : WPerBlock;
        const auto GCPad = math::integer_divide_ceil(GC, GCTile) * GCTile;

        const auto in_n_hw_gc_desc = make_naive_tensor_descriptor_packed(make_tuple(N, HW, GC));

        return transform_tensor_descriptor(in_n_hw_gc_desc,
                                           make_tuple(make_pass_through_transform(N),
                                                      make_right_pad_transform(HW, HWPad - HW),
                                                      make_right_pad_transform(GC, GCPad - GC)),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));
    }

    static auto MakeGridDesc_NGCTildes_C32_HW(const Lengths& g_n_c_wis_lengths)
    {
        const ck::index_t N = g_n_c_wis_lengths[1];
        const ck::index_t G = g_n_c_wis_lengths[0];
        const ck::index_t C = g_n_c_wis_lengths[2];
        const ck::index_t H = g_n_c_wis_lengths[3];
        const ck::index_t W = g_n_c_wis_lengths[4];
        const ck::index_t Cvect = 32;

        const auto CPad    = math::integer_divide_ceil(C, Cvect) * Cvect;
        const auto CTildes = CPad / Cvect;

        const auto HW = H * W;
        const auto HWTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32 ? WPerBlock : HPerBlock;
        const auto HWPad = math::integer_divide_ceil(HW, HWTile) * HWTile;

        const auto NG = N * G;

        const auto in_ng_c_hw_desc = make_naive_tensor_descriptor_packed(make_tuple(NG, C, HW));

        const auto in_ng_cpad_hwpad_desc =
            transform_tensor_descriptor(in_ng_c_hw_desc,
                                        make_tuple(make_pass_through_transform(NG),
                                                   make_right_pad_transform(C, CPad - C),
                                                   make_right_pad_transform(HW, HWPad - HW)),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));

        const auto in_ng_ctildes_cvect_hwpad_desc = transform_tensor_descriptor(
            in_ng_cpad_hwpad_desc,
            make_tuple(make_pass_through_transform(NG),
                       make_unmerge_transform(make_tuple(CTildes, Cvect)),
                       make_pass_through_transform(HWPad)),
            make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
            make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3>{}));

        return transform_tensor_descriptor(
            in_ng_ctildes_cvect_hwpad_desc,
            make_tuple(make_merge_transform(make_tuple(NG, CTildes)),
                       make_pass_through_transform(Cvect),
                       make_pass_through_transform(HWPad)),
            make_tuple(Sequence<0, 1>{}, Sequence<2>{}, Sequence<3>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));
    }

    static auto MakeGridDesc_NGCTildes_HW_C32(const Lengths& g_n_c_wis_lengths)
    {
        const ck::index_t N       = g_n_c_wis_lengths[1];
        const ck::index_t G       = g_n_c_wis_lengths[0];
        const ck::index_t CTildes = g_n_c_wis_lengths[2];
        const ck::index_t H       = g_n_c_wis_lengths[3];
        const ck::index_t W       = g_n_c_wis_lengths[4];
        const ck::index_t Cvect   = 32;

        const auto HW = H * W;
        const auto HWTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32 ? WPerBlock : HPerBlock;
        const auto HWPad = math::integer_divide_ceil(HW, HWTile) * HWTile;

        const auto NGCTildes = N * G * CTildes;

        const auto in_ngctildes_hw_cvect_desc =
            make_naive_tensor_descriptor_packed(make_tuple(NGCTildes, HW, Cvect));

        const auto in_ngctildes_hwpad_cvect_desc =
            transform_tensor_descriptor(in_ngctildes_hw_cvect_desc,
                                        make_tuple(make_pass_through_transform(NGCTildes),
                                                   make_right_pad_transform(HW, HWPad - HW),
                                                   make_pass_through_transform(Cvect)),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));

        return transform_tensor_descriptor(in_ngctildes_hwpad_cvect_desc,
                                           make_tuple(make_pass_through_transform(NGCTildes),
                                                      make_pass_through_transform(HWPad),
                                                      make_pass_through_transform(Cvect)),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));
    }

    static auto MakeGridDesc_NGCTildes_Cvect_HW(const Lengths& g_n_c_wis_lengths, ck::index_t Cvect)
    {
        const ck::index_t N = g_n_c_wis_lengths[1];
        const ck::index_t G = g_n_c_wis_lengths[0];
        const ck::index_t C = g_n_c_wis_lengths[2];
        const ck::index_t H = g_n_c_wis_lengths[3];
        const ck::index_t W = g_n_c_wis_lengths[4];

        const auto CPad    = math::integer_divide_ceil(C, Cvect) * Cvect;
        const auto CTildes = CPad / Cvect;

        const auto HW = H * W;
        const auto HWTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32 ? WPerBlock : HPerBlock;
        const auto HWPad = math::integer_divide_ceil(HW, HWTile) * HWTile;

        const auto NG = N * G;

        const auto in_ng_c_hw_desc = make_naive_tensor_descriptor_packed(make_tuple(NG, C, HW));

        const auto in_ng_cpad_hwpad_desc =
            transform_tensor_descriptor(in_ng_c_hw_desc,
                                        make_tuple(make_pass_through_transform(NG),
                                                   make_right_pad_transform(C, CPad - C),
                                                   make_right_pad_transform(HW, HWPad - HW)),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));

        const auto in_ng_ctildes_cvect_hwpad_desc = transform_tensor_descriptor(
            in_ng_cpad_hwpad_desc,
            make_tuple(make_pass_through_transform(NG),
                       make_unmerge_transform(make_tuple(CTildes, Cvect)),
                       make_pass_through_transform(HWPad)),
            make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
            make_tuple(Sequence<0>{}, Sequence<1, 2>{}, Sequence<3>{}));

        return transform_tensor_descriptor(
            in_ng_ctildes_cvect_hwpad_desc,
            make_tuple(make_merge_transform(make_tuple(NG, CTildes)),
                       make_pass_through_transform(Cvect),
                       make_pass_through_transform(HWPad)),
            make_tuple(Sequence<0, 1>{}, Sequence<2>{}, Sequence<3>{}),
            make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));
    }

    static auto MakeGridDesc_NGCTildes_HW_Cvect(const Lengths& g_n_c_wis_lengths, ck::index_t Cvect)
    {
        const ck::index_t N       = g_n_c_wis_lengths[1];
        const ck::index_t G       = g_n_c_wis_lengths[0];
        const ck::index_t CTildes = g_n_c_wis_lengths[2];
        const ck::index_t H       = g_n_c_wis_lengths[3];
        const ck::index_t W       = g_n_c_wis_lengths[4];

        const auto HW = H * W;
        const auto HWTile =
            TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32 ? WPerBlock : HPerBlock;
        const auto HWPad = math::integer_divide_ceil(HW, HWTile) * HWTile;

        const auto NGCTildes = N * G * CTildes;

        const auto in_ngctildes_hw_cvect_desc =
            make_naive_tensor_descriptor_packed(make_tuple(NGCTildes, HW, Cvect));

        const auto in_ngctildes_hwpad_cvect_desc =
            transform_tensor_descriptor(in_ngctildes_hw_cvect_desc,
                                        make_tuple(make_pass_through_transform(NGCTildes),
                                                   make_right_pad_transform(HW, HWPad - HW),
                                                   make_pass_through_transform(Cvect)),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                        make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));

        return transform_tensor_descriptor(in_ngctildes_hwpad_cvect_desc,
                                           make_tuple(make_pass_through_transform(NGCTildes),
                                                      make_pass_through_transform(HWPad),
                                                      make_pass_through_transform(Cvect)),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}),
                                           make_tuple(Sequence<0>{}, Sequence<1>{}, Sequence<2>{}));
    }

    static auto MakeInGridDesc_N_H_W(const Lengths& g_n_c_wis_lengths)
    {
        if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32)
        {
            return MakeGridDesc_NGCTildes_C32_HW(g_n_c_wis_lengths);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHWc32_TO_NGCHW)
        {
            return MakeGridDesc_NGCTildes_HW_C32(g_n_c_wis_lengths);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc)
        {
            return MakeGridDesc_NGCTildes_Cvect_HW(g_n_c_wis_lengths, OutLayout::x);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHWc_TO_NGCHW)
        {
            return MakeGridDesc_NGCTildes_HW_Cvect(g_n_c_wis_lengths, InLayout::x);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC)
        {
            return MakeGridDesc_N_GC_HW(g_n_c_wis_lengths);
        }
        else
        {
            return MakeGridDesc_N_HW_GC(g_n_c_wis_lengths);
        }
    }

    static auto MakeOutGridDesc_N_W_H(const Lengths& g_n_c_wis_lengths)
    {
        if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32)
        {
            return MakeGridDesc_NGCTildes_HW_C32(g_n_c_wis_lengths);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHWc32_TO_NGCHW)
        {
            return MakeGridDesc_NGCTildes_C32_HW(g_n_c_wis_lengths);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc)
        {
            return MakeGridDesc_NGCTildes_HW_Cvect(g_n_c_wis_lengths, OutLayout::x);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHWc_TO_NGCHW)
        {
            return MakeGridDesc_NGCTildes_Cvect_HW(g_n_c_wis_lengths, InLayout::x);
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC)
        {
            return MakeGridDesc_N_HW_GC(g_n_c_wis_lengths);
        }
        else
        {
            return MakeGridDesc_N_GC_HW(g_n_c_wis_lengths);
        }
    }

    using InGridDesc_N_H_W  = decltype(MakeInGridDesc_N_H_W({}));
    using OutGridDesc_N_W_H = decltype(MakeOutGridDesc_N_W_H({}));

    using GridwiseBatchedTranspose =
        GridwiseBatchedTranspose<InGridDesc_N_H_W,
                                 OutGridDesc_N_W_H,
                                 InDataType,
                                 OutDataType,
                                 BlockSize,
                                 NPerBlock,
                                 HPerBlock,
                                 WPerBlock,
                                 InBlockTransferThreadClusterLengths_N_H_W,
                                 OutBlockTransferThreadClusterLengths_N_W_H,
                                 SrcScalarPerVector,
                                 DstScalarPerVector,
                                 AddLdsExtraH>;

    using Block2TileMap = typename GridwiseBatchedTranspose::DefaultBlock2TileMap;

    struct Argument : public BaseArgument
    {
        Argument(const Lengths& in_g_n_c_wis_lengths,
                 const Lengths& out_g_n_c_wis_lengths,
                 const void* in_dev_buffer,
                 void* out_dev_buffer)
            : in_dev_buffer_(static_cast<const InDataType*>(in_dev_buffer)),
              out_dev_buffer_(static_cast<OutDataType*>(out_dev_buffer)),
              in_grid_desc_(MakeInGridDesc_N_H_W(in_g_n_c_wis_lengths)),
              out_grid_desc_(MakeOutGridDesc_N_W_H(out_g_n_c_wis_lengths)),
              in_lengths_(in_g_n_c_wis_lengths),
              out_lengths_(out_g_n_c_wis_lengths),
              num_block_iterations_(1),
              block_2_tile_map_(GridwiseBatchedTranspose::MakeDefaultBlock2TileMap(in_grid_desc_))
        {
        }

        const InDataType* in_dev_buffer_;
        OutDataType* out_dev_buffer_;
        InGridDesc_N_H_W in_grid_desc_;
        OutGridDesc_N_W_H out_grid_desc_;

        Lengths in_lengths_;
        Lengths out_lengths_;

        ck::index_t num_block_iterations_;

        Block2TileMap block_2_tile_map_;

        void Print() const
        {
            std::cout << "In[N, H, W]: " << in_grid_desc_ << std::endl;
            std::cout << "Out[N, W, H]: " << out_grid_desc_ << std::endl;
        }
    };

    struct Invoker : BaseInvoker
    {
        static float Run(const Argument& arg, const StreamConfig& stream_config = StreamConfig{})
        {
            const index_t grid_size = arg.block_2_tile_map_.CalculateGridSize(
                arg.in_grid_desc_, arg.num_block_iterations_);

            // 16 waves per CU
            constexpr index_t WaveSize      = 64;
            constexpr index_t MinWavePerCu  = 16;
            constexpr index_t WavesPerBlock = BlockSize / WaveSize;
            constexpr index_t MinBlockPerCU = MinWavePerCu / WavesPerBlock;

            const auto kernel = kernel_batched_transpose<BlockSize,
                                                         MinBlockPerCU,
                                                         GridwiseBatchedTranspose,
                                                         InGridDesc_N_H_W,
                                                         OutGridDesc_N_W_H,
                                                         InDataType,
                                                         OutDataType,
                                                         Block2TileMap>;

            float elapsed_time = launch_and_time_kernel(stream_config,
                                                        kernel,
                                                        dim3(grid_size),
                                                        dim3(BlockSize),
                                                        0,
                                                        arg.in_grid_desc_,
                                                        arg.out_grid_desc_,
                                                        arg.in_dev_buffer_,
                                                        arg.out_dev_buffer_,
                                                        arg.num_block_iterations_,
                                                        arg.block_2_tile_map_);
            return elapsed_time;
        }

        float Run(const BaseArgument* arg,
                  const StreamConfig& stream_config = StreamConfig{}) override final
        {
            const auto* const argument = dynamic_cast<const Argument*>(arg);
            if(!argument)
            {
                return NAN;
            }

            return Run(*argument, stream_config);
        }
    }; // namespace device

    static bool IsSupportedArgument(const Argument& arg)
    {
        if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc32)
        {
            const auto HW = arg.in_lengths_[3] * arg.in_lengths_[4];
            if(HW % SrcScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHWc32_TO_NGCHW)
        {
            const auto HW = arg.out_lengths_[3] * arg.out_lengths_[4];
            if(HW % DstScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NGCHWc)
        {
            const auto HW = arg.in_lengths_[3] * arg.in_lengths_[4];
            if(HW % SrcScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHWc_TO_NGCHW)
        {
            const auto HW = arg.out_lengths_[3] * arg.out_lengths_[4];
            if(HW % DstScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NGCHW_TO_NHWGC)
        {
            const auto HW = arg.in_lengths_[3] * arg.in_lengths_[4];
            const auto GC = arg.in_lengths_[0] * arg.in_lenghts_[2];

            if(HW % SrcScalarPerVector != 0)
            {
                return false;
            }

            if(GC % DstScalarPerVector != 0)
            {
                return false;
            }
        }
        else if constexpr(TransType == LayoutTransformSpecialization::NHWGC_TO_NGCHW)
        {
            const auto GC = arg.in_lengths_[0] * arg.in_lenghts_[2];
            const auto HW = arg.out_lenghts_[3] * arg.out_lengths_[4];

            if(GC % SrcScalarPerVector != 0)
            {
                return false;
            }

            if(HW % DstScalarPerVector != 0)
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        return GridwiseBatchedTranspose::CheckValidity(arg.in_grid_desc_, arg.out_grid_desc_);
    };

    // override methods inherited from 'BaseOperator'
    bool IsSupportedArgument(const BaseArgument* arg) override final
    {
        const auto* const argument = dynamic_cast<const Argument*>(arg);
        if(!argument)
        {
            return false;
        }

        return IsSupportedArgument(*argument);
    }

    // override methods inherited from 'DevicePermute'
    std::unique_ptr<BaseArgument> MakeArgumentPointer(const Lengths& in_g_n_c_wis_lengths,
                                                      const Lengths& out_g_n_c_wis_lengths,
                                                      const void* in_dev_buffer,
                                                      void* out_dev_buffer) override final
    {
        return std::make_unique<Argument>(
            in_g_n_c_wis_lengths, out_g_n_c_wis_lengths, in_dev_buffer, out_dev_buffer);
    }

    std::unique_ptr<BaseInvoker> MakeInvokerPointer() override final
    {
        return std::make_unique<Invoker>();
    }

    std::string GetTypeString() const override
    {
        auto str = std::stringstream();

        // clang-format off
        str << "DeviceLayoutTrans"
            << "-"
            << BlockSize << "-"
            << NPerBlock << "-"
            << HPerBlock << "-"
            << WPerBlock << "-"
            << SrcScalarPerVector << "-"
            << DstScalarPerVector;
        if constexpr(AddLdsExtraH)
            str << "-PadLDS";
        // clang-format on

        return str.str();
    }
}; // namespace tensor_operation

} // namespace device
} // namespace tensor_operation
} // namespace ck
