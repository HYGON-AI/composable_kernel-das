// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <cstdlib>

#include "ck/ck.hpp"
#include "ck/tensor_operation/gpu/device/impl/device_grouped_conv_fwd_mmac_nchw_v2_cshuffle.hpp"
#include "ck/tensor_operation/gpu/device/convolution_forward_specialization.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"
#include "ck/library/tensor_operation_instance/add_device_operation_instance.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

template <ck::index_t... Is>
using S = ck::Sequence<Is...>;

using InLayout  = ck::tensor_layout::convolution::NGCHW;
using WeiLayout = ck::tensor_layout::convolution::GKCYX;
using OutLayout = ck::tensor_layout::convolution::NGKHW;

using InElementOp  = ck::tensor_operation::element_wise::PassThrough;
using WeiElementOp = ck::tensor_operation::element_wise::PassThrough;
using OutElementOp = ck::tensor_operation::element_wise::PassThrough;

// conv spec alias
static constexpr auto ConvFwd1x1S1P0 =
    ck::tensor_operation::device::ConvolutionForwardSpecialization::Filter1x1Stride1Pad0;

using device_instances = std::tuple<
    // clang-format off
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 1, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 4, 1, 16, 8>, 4, 4, S<1, 128, 4>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 1, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 8, 1, 16, 4>, 4, 8, S<1, 128, 4>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 1, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 4, 1, 16, 8>, 4, 4, S<1, 128, 4>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 2>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 1, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 8, 1, 16, 4>, 4, 8, S<1, 128, 4>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 2>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 64, 2, 16, 16, 16, 4, 2, 1, 1, 2, 1, S<1, 2, 2, 16, 8>, 4, 4, S<1, 64, 8>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 2, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 2, 2, 16, 8>, 4, 4, S<1, 64, 8>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 2, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 2, 2, 16, 8>, 4, 4, S<1, 128, 4>, 2, 8, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 64, 2, 16, 16, 16, 4, 2, 1, 1, 2, 1, S<1, 4, 2, 16, 4>, 4, 8, S<1, 64, 8>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 2, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 4, 2, 16, 4>, 4, 8, S<1, 64, 8>, 2, 4, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>,
DeviceGroupedConvFwd_mmac_nchw_v2_cshuffle<2, InLayout, WeiLayout, OutLayout, ck::half_t, ck::half_t, float, ck::half_t, InElementOp, WeiElementOp, OutElementOp, ConvFwd1x1S1P0, 512, 16, 32, 128, 2, 16, 16, 16, 4, 4, 1, 1, 2, 1, S<1, 4, 2, 16, 4>, 4, 8, S<1, 128, 4>, 2, 8, 1, 1, S<1, 1, 16, 1, 1, 32>, 4, 1>
    // clang-format on
    >;

void add_device_grouped_conv2d_fwd_mmac_v2_ngchw_gkcyx_ngkhw_f16_f16_f16_gfx936_f1x1s1p0_cshuffle_8wave_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     InLayout,
                                                     WeiLayout,
                                                     OutLayout,
                                                     ck::half_t,
                                                     ck::half_t,
                                                     ck::half_t,
                                                     InElementOp,
                                                     WeiElementOp,
                                                     OutElementOp>>>& instances)
{
    add_device_operation_instances(instances, device_instances{});
}
} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
