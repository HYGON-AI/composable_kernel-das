// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <cstdlib>

#include "ck/ck.hpp"
#include "ck/tensor_operation/gpu/device/impl_ck_tile_wrapper/fused_conv_wasp_kernel_v2r1_cba_wrapper.hpp"
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
using OutElemOp = ck::tensor_operation::element_wise::Add;

// conv spec alias
static constexpr auto ConvSpec = ck_tile::ConvFwdSpec::Filter1x1Pad0;

template <ck_tile::index_t MWGs,
          ck_tile::index_t NWGs,
          ck_tile::index_t MPerWG,
          ck_tile::index_t NPerWG,
          ck_tile::index_t KPerBlock,
          ck_tile::index_t NumPrefetch>
using Kernel = FusedConvWaspKernelV2R1_CBA_Wrapper<2,
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
                                                   ConvSpec,
                                                   MWGs,
                                                   NWGs,
                                                   MPerWG,
                                                   NPerWG,
                                                   KPerBlock,
                                                   2,
                                                   2,
                                                   S<8, 8>,
                                                   S<8, 8>,
                                                   8,
                                                   NumPrefetch>;

template <ck::index_t NumPrefetch>
using device_instances = std::tuple<
    // clang-format off
    Kernel<2, 1, 256,  64, 32, 2>,
    Kernel<2, 1, 128, 128, 32, NumPrefetch>,
    Kernel<2, 1, 128,  64, 32, NumPrefetch>,
    Kernel<2, 1, 64,  256, 32, 2>,
    Kernel<2, 1, 64,  128, 32, NumPrefetch>,
    Kernel<2, 1, 64,   64, 32, NumPrefetch>,
    
    Kernel<1, 2, 256,  64, 32, 2>,
    Kernel<1, 2, 128, 128, 32, NumPrefetch>,
    Kernel<1, 2, 128,  64, 32, NumPrefetch>,
    Kernel<1, 2, 64,  256, 32, 2>,
    Kernel<1, 2, 64,  128, 32, NumPrefetch>,
    Kernel<1, 2, 64,   64, 32, NumPrefetch>
    // clang-format on
    >;

void add_fused_conv2d_v2r1_cb_nhwgc_gkyxc_nhwgk_f16_f16_f16_f16_gfx936_f1x1p0_instances(
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
