// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#include <cstdlib>

#include "ck/ck.hpp"
#include "ck/tensor_operation/gpu/device/impl/device_grouped_conv_bwd_weight_mmac_v2_oddc.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_weight_specialization.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"
#include "ck/library/tensor_operation_instance/add_device_operation_instance.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

template <ck::index_t... Is>
using S = ck::Sequence<Is...>;

using OutLayout = ck::tensor_layout::convolution::NDHWGK;
using InLayout  = ck::tensor_layout::convolution::NDHWGC;
using WeiLayout = ck::tensor_layout::convolution::GKZYXC;

using OutElementOp = ck::tensor_operation::element_wise::PassThrough;
using InElementOp  = ck::tensor_operation::element_wise::PassThrough;
using WeiElementOp = ck::tensor_operation::element_wise::PassThrough;

static constexpr index_t NDimSpatial = 3;

static constexpr auto ConvWrwDefault =
    ck::tensor_operation::device::ConvolutionBackwardWeightSpecialization::Default;

template <ck::index_t NumPrefetchStage, ck::index_t GemmKSplitFactor>
using device_instances = std::tuple<
    // clang-format off
DeviceGroupedConvBwdWeight_mmac_v2_oddc<NDimSpatial, OutLayout, InLayout, WeiLayout, ck::half_t, ck::half_t, float, float, OutElementOp, InElementOp, WeiElementOp, ConvWrwDefault, 256, 2, 32, 4, 32, 1, 16, 16, 16, 1, 1, 4, 2, 1, 1, S<1, 2, 1, 16, 8>, 4, 4, S<1, 1, 1, 8, 32>, 4, 1, NumPrefetchStage, GemmKSplitFactor>
    // clang-format on
    >;

void add_device_grouped_conv3d_wrw_mmac_v2_ndhwgk_ndhwgc_gkzyxc_f16_f16_f32_gfx936_oddc_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvBwdWeightV2<NDimSpatial,
                                                             OutLayout,
                                                             InLayout,
                                                             WeiLayout,
                                                             ck::half_t,
                                                             ck::half_t,
                                                             float,
                                                             OutElementOp,
                                                             InElementOp,
                                                             WeiElementOp>>>& instances)
{

    // prefetch stage 1, split factor 2
    add_device_operation_instances(instances, device_instances<1, 2>{});

    // prefetch stage 1, split factor 4
    add_device_operation_instances(instances, device_instances<1, 4>{});

    // prefetch stage 1, split factor 8
    add_device_operation_instances(instances, device_instances<1, 8>{});

    // prefetch stage 2, split factor 2
    add_device_operation_instances(instances, device_instances<2, 2>{});

    // prefetch stage 2, split factor 4
    add_device_operation_instances(instances, device_instances<2, 4>{});

    // prefetch stage 2, split factor 8
    add_device_operation_instances(instances, device_instances<2, 8>{});
}
} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
