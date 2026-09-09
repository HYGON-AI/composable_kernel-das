// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <cstdlib>

#include "ck/ck.hpp"
#include "ck/tensor_operation/gpu/device/impl_ck_tile_wrapper/fused_conv_mls_wasp_kernel_v1_cba_wrapper.hpp"
#include "ck/tensor_operation/gpu/device/convolution_forward_specialization.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"
#include "ck/library/tensor_operation_instance/add_device_operation_instance.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

template <ck::index_t... Is>
using S = ck_tile::sequence<Is...>;

using InLayout  = ck::tensor_layout::convolution::NHWGC;
using WeiLayout = ck::tensor_layout::convolution::GKYXC;
using OutLayout = ck::tensor_layout::convolution::NHWGK;

using InElemOp  = ck::tensor_operation::element_wise::PassThrough;
using WeiElemOp = ck::tensor_operation::element_wise::PassThrough;
using OutElemOp = ck::tensor_operation::element_wise::AddRelu;

template <ck_tile::index_t MWGs,
          ck_tile::index_t NWGs,
          ck_tile::index_t MPerWG,
          ck_tile::index_t NPerWG,
          ck_tile::index_t KPerBlock,
          ck_tile::index_t NumLdsStages>
using Kernel = FusedConvMlsWaspKernelV1_CBA_Wrapper<ck_tile::hcu_target_enum::gfx938,
                                                    2,
                                                    InLayout,
                                                    WeiLayout,
                                                    OutLayout,
                                                    ck::half_t,
                                                    ck::half_t,
                                                    float,
                                                    ck::half_t,
                                                    ck::half_t,
                                                    InElemOp,
                                                    WeiElemOp,
                                                    OutElemOp,
                                                    MWGs,
                                                    NWGs,
                                                    MPerWG,
                                                    NPerWG,
                                                    KPerBlock,
                                                    8,
                                                    NumLdsStages>;

template <ck::index_t NumLdsStages>
using device_instances = std::tuple<
    // clang-format off
    Kernel<2, 1, 128, 256, 32, NumLdsStages>,
    Kernel<2, 1, 128, 128, 32, NumLdsStages>,
    Kernel<2, 1, 128,  64, 32, NumLdsStages>,
    Kernel<2, 1, 64,  256, 32, NumLdsStages>,
    Kernel<2, 1, 64,  128, 32, NumLdsStages>,
    Kernel<2, 1, 64,   64, 32, NumLdsStages>,

    Kernel<1, 2, 256, 128, 32, NumLdsStages>,
    Kernel<1, 2, 128, 128, 32, NumLdsStages>,
    Kernel<1, 2, 64,  128, 32, NumLdsStages>,
    Kernel<1, 2, 256,  64, 32, NumLdsStages>,
    Kernel<1, 2, 128,  64, 32, NumLdsStages>,
    Kernel<1, 2, 64,   64, 32, NumLdsStages>,

    Kernel<2, 1, 128, 128, 64, NumLdsStages>,
    Kernel<2, 1, 128,  64, 64, NumLdsStages>,
    Kernel<2, 1, 64,  256, 64, NumLdsStages>,
    Kernel<2, 1, 64,  128, 64, NumLdsStages>,
    Kernel<2, 1, 64,   64, 64, NumLdsStages>,

    Kernel<1, 2, 256,  64, 64, NumLdsStages>,
    Kernel<1, 2, 128, 128, 64, NumLdsStages>,
    Kernel<1, 2, 128,  64, 64, NumLdsStages>,
    Kernel<1, 2, 64,  128, 64, NumLdsStages>,
    Kernel<1, 2, 64,   64, 64, NumLdsStages>
    // clang-format on
    >;

void add_fused_mls_conv2d_v1_cba_nhwgc_gkyxc_nhwgk_f16_f16_f16_f16_gfx938_f1x1s1p0_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwdBiasActivation<2,
                                                                   InLayout,
                                                                   WeiLayout,
                                                                   OutLayout,
                                                                   ck::half_t,
                                                                   ck::half_t,
                                                                   ck::half_t,
                                                                   ck::half_t,
                                                                   InElemOp,
                                                                   WeiElemOp,
                                                                   OutElemOp>>>& instances)
{
    // prefetch stage 2
    add_device_operation_instances(instances, device_instances<2>{});

    // prefetch stage 4
    add_device_operation_instances(instances, device_instances<4>{});
}
} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
