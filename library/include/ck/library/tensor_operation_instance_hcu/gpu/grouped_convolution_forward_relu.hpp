// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <memory>
#include <vector>

#include "ck/ck.hpp"
#include "ck/host_utility/device_prop.hpp"
#include "ck/tensor_operation/gpu/device/device_grouped_conv_fwd.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"

#include "ck/library/tensor_operation_instance_hcu/device_operation_instance_factory.hpp"

namespace ck {

namespace tensor_operation {
namespace device {
namespace instance {

// device_grouped_conv2d_fwd_relu_mmac_v2_cshuffle instances
void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhwk32_f16_f16_f16_gfx936_default_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHWk32,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhwk32_f16_f16_f16_gfx936_f1x1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHWk32,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhwk32_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHWk32,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

// device_grouped_conv2d_fwd_relu_mmac_v2_cshuffle_mixed instances
void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhw_f16_f16_f16_gfx936_default_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHW,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhw_f16_f16_f16_gfx936_f1x1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHW,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhw_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHW,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

// device_grouped_conv2d_fwd_relu_mmac_nchw_v2_cshuffle instances
void add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchw_gkcyx_ngkhw_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHW,
                                                     GKCYX,
                                                     NGKHW,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

// device_grouped_conv2d_fwd_relu_mmac_nhwgc_v2_cshuffle instances
void add_device_grouped_conv2d_fwd_relu_mmac_v2_nhwgc_gkyxc_nhwgk_f16_f16_f16_gfx936_default_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NHWGC,
                                                     GKYXC,
                                                     NHWGK,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

void add_device_grouped_conv2d_fwd_relu_mmac_v2_nhwgc_gkyxc_nhwgk_f16_f16_f16_gfx936_f1x1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NHWGC,
                                                     GKYXC,
                                                     NHWGK,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);

void add_device_grouped_conv2d_fwd_relu_mmac_v2_nhwgc_gkyxc_nhwgk_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NHWGC,
                                                     GKYXC,
                                                     NHWGK,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     Relu>>>& instances);                                                     
                                                    

template <ck::index_t NumDimSpatial,
          typename InLayout,
          typename WeiLayout,
          typename OutLayout,
          typename InDataType,
          typename WeiDataType,
          typename OutDataType>
struct DeviceOperationInstanceFactory<DeviceGroupedConvFwd<NumDimSpatial,
                                                           InLayout,
                                                           WeiLayout,
                                                           OutLayout,
                                                           InDataType,
                                                           WeiDataType,
                                                           OutDataType,
                                                           PassThrough,
                                                           PassThrough,
                                                           Relu>>
{
    using DeviceOp = DeviceGroupedConvFwd<NumDimSpatial,
                                          InLayout,
                                          WeiLayout,
                                          OutLayout,
                                          InDataType,
                                          WeiDataType,
                                          OutDataType,
                                          PassThrough,
                                          PassThrough,
                                          Relu>;

    static auto GetInstances()
    {
        std::vector<std::unique_ptr<DeviceOp>> op_ptrs;

        static const auto hcu_target_enum = ck::get_hcu_target_enum();

        if constexpr(NumDimSpatial == 2)
        {
            if constexpr(is_same_v<InLayout, NHWGC> && is_same_v<WeiLayout, GKYXC> &&
                         is_same_v<OutLayout, NHWGK>)
            {
                if constexpr(is_same_v<InDataType, F16> && is_same_v<WeiDataType, F16> &&
                             is_same_v<OutDataType, F16>)
                {
                    if(ck::is_gfx936_family(hcu_target_enum))
                    {
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_nhwgc_gkyxc_nhwgk_f16_f16_f16_gfx936_default_cshuffle_instances(
                            op_ptrs);
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_nhwgc_gkyxc_nhwgk_f16_f16_f16_gfx936_f1x1p0_cshuffle_instances(
                            op_ptrs);
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_nhwgc_gkyxc_nhwgk_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
                            op_ptrs);
                    }
                }
            }
            if constexpr(is_same_v<InLayout, NGCHWc32> && is_same_v<WeiLayout, GKCYXc32> &&
                         is_same_v<OutLayout, NGKHWk32>)
            {
                if constexpr(is_same_v<InDataType, F16> && is_same_v<WeiDataType, F16> &&
                             is_same_v<OutDataType, F16>)
                {
                    if(ck::is_gfx936_family(hcu_target_enum))
                    {
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhwk32_f16_f16_f16_gfx936_default_cshuffle_instances(
                            op_ptrs);
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhwk32_f16_f16_f16_gfx936_f1x1p0_cshuffle_instances(
                            op_ptrs);
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhwk32_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
                            op_ptrs);
                    }
                }
            }
            if constexpr(is_same_v<InLayout, NGCHWc32> && is_same_v<WeiLayout, GKCYXc32> &&
                         is_same_v<OutLayout, NGKHW>)
            {
                if constexpr(is_same_v<InDataType, F16> && is_same_v<WeiDataType, F16> &&
                             is_same_v<OutDataType, F16>)
                {
                    if(ck::is_gfx936_family(hcu_target_enum))
                    {
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhw_f16_f16_f16_gfx936_default_cshuffle_instances(
                            op_ptrs);
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhw_f16_f16_f16_gfx936_f1x1p0_cshuffle_instances(
                            op_ptrs);
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchwc32_gkcyxc32_ngkhw_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
                            op_ptrs);
                    }
                }
            }
            if constexpr(is_same_v<InLayout, NGCHW> && is_same_v<WeiLayout, GKCYX> &&
                         is_same_v<OutLayout, NGKHW>)
            {
                if constexpr(is_same_v<InDataType, F16> && is_same_v<WeiDataType, F16> &&
                             is_same_v<OutDataType, F16>)
                {
                    if(ck::is_gfx936_family(hcu_target_enum))
                    {
                        add_device_grouped_conv2d_fwd_relu_mmac_v2_ngchw_gkcyx_ngkhw_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_instances(
                            op_ptrs);
                    }
                }
            }
            else if constexpr(is_same_v<InLayout, NGCHWc16> && is_same_v<WeiLayout, GKCYXc16> &&
                              is_same_v<OutLayout, NGKHWk16>)
            {
            }
        }

        return op_ptrs;
    }
};

} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
