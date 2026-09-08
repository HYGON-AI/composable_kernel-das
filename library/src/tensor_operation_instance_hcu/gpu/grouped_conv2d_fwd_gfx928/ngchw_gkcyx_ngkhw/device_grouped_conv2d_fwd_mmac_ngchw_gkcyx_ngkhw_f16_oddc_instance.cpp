// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#include <memory>
#include <tuple>

#include "ck/library/tensor_operation_instance_hcu/add_device_operation_instance.hpp"
#include "device_grouped_conv2d_fwd_common.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

template <ConvolutionForwardSpecialization ConvFwdSpec,
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
          ck::index_t ABlockTransferSrcScalarPerVector,
          ck::index_t ABlockTransferDstScalarPerVector_K1,
          bool ABlockLdsAddExtraM,
          typename BBlockTransferThreadClusterLengths_K0_N_K1,
          ck::index_t BBlockTransferSrcScalarPerVector,
          ck::index_t BBlockTransferDstScalarPerVector_K1,
          bool BBlockLdsAddExtraN,
          ck::index_t NumGemmKPrefetchStage>
using DeviceOpF16 = DeviceOp<NGCHW,
                             GKCYX,
                             NGKHW,
                             F16,
                             F16,
                             F16,
                             ConvFwdSpec,
                             BlockSize,
                             MPerBlock,
                             NPerBlock,
                             K0PerBlock,
                             K1,
                             MPerMmac,
                             NPerMmac,
                             MMmacPerWave,
                             NMmacPerWave,
                             ABlockTransferThreadClusterLengths_K0_M_K1,
                             ABlockTransferSrcScalarPerVector,
                             ABlockTransferDstScalarPerVector_K1,
                             ABlockLdsAddExtraM,
                             BBlockTransferThreadClusterLengths_K0_N_K1,
                             BBlockTransferSrcScalarPerVector,
                             BBlockTransferDstScalarPerVector_K1,
                             BBlockLdsAddExtraN,
                             NumGemmKPrefetchStage>;

using device_instances = std::tuple<
    // clang-format off
    DeviceOpF16<ConvFwdDefault, 512, 512, 64, 4, 8, 16, 16, 8, 2, S<4, 128, 1>, 1, 8, true, S<4, 64, 2>, 1, 4, true, 1>,
    DeviceOpF16<ConvFwdDefault, 512, 512, 64, 4, 4, 16, 16, 8, 2, S<4, 128, 1>, 1, 4, true, S<4, 64, 2>, 1, 2, true, 1>,
    DeviceOpF16<ConvFwdDefault, 512, 512, 32, 4, 8, 16, 16, 8, 1, S<4, 128, 1>, 1, 8, true, S<4, 32, 4>, 1, 2, true, 1>,
    DeviceOpF16<ConvFwdDefault, 256, 256, 64, 8, 8, 16, 16, 8, 2, S<8, 32, 1>, 1, 8, true, S<8, 32, 1>, 1, 8, true, 1>,
    DeviceOpF16<ConvFwdDefault, 256, 256, 64, 4, 8, 16, 16, 8, 2, S<4, 64, 1>, 1, 8, true, S<4, 64, 1>, 1, 8, true, 1>,
    DeviceOpF16<ConvFwdDefault, 256, 128, 64, 8, 8, 16, 16, 4, 2, S<8, 32, 1>, 1, 8, true, S<8, 32, 1>, 1, 8, true, 1>,
    DeviceOpF16<ConvFwdDefault, 256, 128, 64, 4, 8, 16, 16, 4, 2, S<4, 64, 1>, 1, 8, true, S<4, 64, 1>, 1, 8, true, 1>,
    DeviceOpF16<ConvFwdDefault, 256, 256, 64, 4, 8, 16, 16, 8, 2, S<4, 64, 1>, 1, 8, true, S<4, 64, 1>, 1, 8, true, 2>,
    DeviceOpF16<ConvFwdDefault, 256, 128, 64, 8, 8, 16, 16, 4, 2, S<8, 32, 1>, 1, 8, true, S<8, 32, 1>, 1, 8, true, 2>,
    DeviceOpF16<ConvFwdDefault, 256, 128, 64, 4, 8, 16, 16, 4, 2, S<4, 64, 1>, 1, 8, true, S<4, 64, 1>, 1, 8, true, 2>
    // clang-format on
    >;

void add_device_grouped_conv2d_fwd_mmac_ngchw_gkcyx_ngkhw_f16_oddc_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHW,
                                                     GKCYX,
                                                     NGKHW,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     PassThrough>>>& instances)
{
    add_device_operation_instances(instances, device_instances{});
}

} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
