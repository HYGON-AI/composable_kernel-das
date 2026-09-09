// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <memory>
#include <tuple>

#include "ck/library/tensor_operation_instance_hcu/add_device_operation_instance.hpp"
#include "device_grouped_conv2d_fwd_common.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

// TODO: support elementwise op?
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
using DeviceOpF16 = DeviceOp<NGCHWc32,
                             GKCYXc32,
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

template <ck::index_t NumGemmKPrefetchStage>
using device_instances = std::tuple<
    // clang-format off
    // K: 8x8
    DeviceOpF16<ConvFwd1x1S1P0, 256, 256, 128, 8, 8, 16, 16, 8, 4, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 256, 8, 8, 16, 16, 4, 8, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 128, 8, 8, 16, 16, 4, 4, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 64,  8, 8, 16, 16, 4, 2, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 64,  128, 8, 8, 16, 16, 2, 4, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 32,  8, 8, 16, 16, 4, 1, S<4, 64, 1>, 8, 8, true, S<8, 32, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 32,  128, 8, 8, 16, 16, 1, 4, S<8, 32, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 64,  64,  8, 8, 16, 16, 2, 2, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,


    // K: 4x8
    DeviceOpF16<ConvFwd1x1S1P0, 256, 256, 128, 4, 8, 16, 16, 8, 4, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 256, 4, 8, 16, 16, 4, 8, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 64,  4, 8, 16, 16, 4, 2, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 64,  128, 4, 8, 16, 16, 2, 4, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 128, 32,  4, 8, 16, 16, 4, 1, S<4, 64, 1>, 8, 8, true, S<4, 32, 2>, 4, 4, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 32,  128, 4, 8, 16, 16, 1, 4, S<4, 32, 2>, 4, 4, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>,
    DeviceOpF16<ConvFwd1x1S1P0, 256, 64,  64,  4, 8, 16, 16, 2, 2, S<4, 64, 1>, 8, 8, true, S<4, 64, 1>, 8, 8, true, NumGemmKPrefetchStage>
    // clang-format on
    >;

void add_device_grouped_conv2d_fwd_mmac_ngchwc32_gkcyxc32_ngkhw_f16_f1x1s1p0_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NGCHWc32,
                                                     GKCYXc32,
                                                     NGKHW,
                                                     F16,
                                                     F16,
                                                     F16,
                                                     PassThrough,
                                                     PassThrough,
                                                     PassThrough>>>& instances)
{
    // prefetch 1
    add_device_operation_instances(instances, device_instances<1>{});

    // prefetch 2
    add_device_operation_instances(instances, device_instances<2>{});
}

} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
