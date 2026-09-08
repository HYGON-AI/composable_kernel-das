// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#include <memory>
#include <tuple>

#include "ck/library/tensor_operation_instance_hcu/add_device_operation_instance.hpp"
#include "device_grouped_conv2d_bwd_weight_common.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

// TODO: support elementwise op?
template <ConvolutionBackwardWeightSpecialization ConvBwdWeightSpec,
          ck::index_t BlockSize,
          ck::index_t MPerBlock,
          ck::index_t NPerBlock,
          ck::index_t K0PerBlock,
          ck::index_t K1,
          ck::index_t MPerMmac,
          ck::index_t NPerMmac,
          ck::index_t MMmacPerWave,
          ck::index_t NMmacPerWave,
          typename ABlockTransferThreadClusterLengths_B_K0_M_K1,
          ck::index_t ABlockTransferSrcScalarPerVector,
          ck::index_t ABlockTransferDstScalarPerVector_K1,
          bool ABlockLdsAddExtraM,
          typename BBlockTransferThreadClusterLengths_B_K0_N_K1,
          ck::index_t BBlockTransferSrcScalarPerVector,
          ck::index_t BBlockTransferDstScalarPerVector_K1,
          bool BBlockLdsAddExtraN,
          ck::index_t NumGemmKPrefetchStage,
          ck::index_t GemmKSplitFactor>
using DeviceOpF16 = DeviceOp<F16,
                             F16,
                             F32,
                             ConvBwdWeightSpec,
                             BlockSize,
                             MPerBlock,
                             NPerBlock,
                             K0PerBlock,
                             K1,
                             MPerMmac,
                             NPerMmac,
                             MMmacPerWave,
                             NMmacPerWave,
                             ABlockTransferThreadClusterLengths_B_K0_M_K1,
                             ABlockTransferSrcScalarPerVector,
                             ABlockTransferDstScalarPerVector_K1,
                             ABlockLdsAddExtraM,
                             BBlockTransferThreadClusterLengths_B_K0_N_K1,
                             BBlockTransferSrcScalarPerVector,
                             BBlockTransferDstScalarPerVector_K1,
                             BBlockLdsAddExtraN,
                             NumGemmKPrefetchStage,
                             GemmKSplitFactor>;

template <ck::index_t NumGemmKPrefetchStage = 1, ck::index_t GemmKSplitFactor = 1>
using device_instances = std::tuple<
    // clang-format off
    // 4-wave

    // K: 8x8
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 128, 8, 8, 16, 16, 4, 4, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 128, 8, 8, 16, 16, 4, 4, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 128, 8, 8, 16, 16, 4, 4, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 64, 8, 8, 16, 16, 4, 2, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 64, 8, 8, 16, 16, 4, 2, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 64, 8, 8, 16, 16, 4, 2, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 128, 8, 8, 16, 16, 2, 4, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 128, 8, 8, 16, 16, 2, 4, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 128, 8, 8, 16, 16, 2, 4, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 32, 8, 8, 16, 16, 4, 1, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 32, 8, 8, 16, 16, 4, 1, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 32, 8, 8, 16, 16, 4, 1, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 32, 128, 8, 8, 16, 16, 1, 4, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 32, 128, 8, 8, 16, 16, 1, 4, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 32, 128, 8, 8, 16, 16, 1, 4, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 64, 8, 8, 16, 16, 2, 2, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 64, 8, 8, 16, 16, 2, 2, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 64, 8, 8, 16, 16, 2, 2, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 32, 8, 8, 16, 16, 2, 1, S<1, 8, 32, 1>, 1, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 32, 8, 8, 16, 16, 2, 1, S<1, 8, 32, 1>, 4, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 32, 8, 8, 16, 16, 2, 1, S<1, 8, 32, 1>, 8, 8, true, S<1, 8, 32, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    
    // K: 4x8
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<1, 4, 64, 1>, 1, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<1, 4, 64, 1>, 4, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<1, 4, 64, 1>, 8, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 64, 4, 8, 16, 16, 4, 2, S<1, 4, 64, 1>, 1, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 64, 4, 8, 16, 16, 4, 2, S<1, 4, 64, 1>, 4, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 64, 4, 8, 16, 16, 4, 2, S<1, 4, 64, 1>, 8, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 128, 4, 8, 16, 16, 2, 4, S<1, 4, 64, 1>, 1, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 128, 4, 8, 16, 16, 2, 4, S<1, 4, 64, 1>, 4, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 128, 4, 8, 16, 16, 2, 4, S<1, 4, 64, 1>, 8, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 32, 4, 8, 16, 16, 4, 1, S<1, 4, 64, 1>, 1, 8, true, S<1, 4, 32, 2>, 1, 4, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 32, 4, 8, 16, 16, 4, 1, S<1, 4, 64, 1>, 4, 8, true, S<1, 4, 32, 2>, 1, 4, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 128, 32, 4, 8, 16, 16, 4, 1, S<1, 4, 64, 1>, 8, 8, true, S<1, 4, 32, 2>, 1, 4, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 32, 128, 4, 8, 16, 16, 1, 4, S<1, 4, 32, 2>, 1, 4, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 32, 128, 4, 8, 16, 16, 1, 4, S<1, 4, 32, 2>, 4, 4, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 64, 4, 8, 16, 16, 2, 2, S<1, 4, 64, 1>, 1, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 64, 4, 8, 16, 16, 2, 2, S<1, 4, 64, 1>, 4, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 64, 4, 8, 16, 16, 2, 2, S<1, 4, 64, 1>, 8, 8, true, S<1, 4, 64, 1>, 1, 8, true, NumGemmKPrefetchStage, GemmKSplitFactor>,

    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 32, 4, 8, 16, 16, 2, 1, S<1, 4, 64, 1>, 1, 8, true, S<1, 4, 32, 2>, 1, 4, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 32, 4, 8, 16, 16, 2, 1, S<1, 4, 64, 1>, 4, 8, true, S<1, 4, 32, 2>, 1, 4, true, NumGemmKPrefetchStage, GemmKSplitFactor>,
    DeviceOpF16<ConvBwdWeightDefault, 256, 64, 32, 4, 8, 16, 16, 2, 1, S<1, 4, 64, 1>, 8, 8, true, S<1, 4, 32, 2>, 1, 4, true, NumGemmKPrefetchStage, GemmKSplitFactor>
    // clang-format on
    >;

void add_device_grouped_conv2d_bwd_weight_mmac_ngkhw_ngchw_gkcyx_f16_default_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvBwdWeightV2<2,
                                                             NGKHW,
                                                             NGCHW,
                                                             GKCYX,
                                                             F16,
                                                             F16,
                                                             F32,
                                                             PassThrough,
                                                             PassThrough,
                                                             PassThrough>>>& instances)
{
    // prefetch 1, ksplit factor: 2
    add_device_operation_instances(instances, device_instances<1, 2>{});

    // prefetch 2, ksplit factor: 2
    add_device_operation_instances(instances, device_instances<2, 2>{});

    // prefetch 1, ksplit factor: 4
    add_device_operation_instances(instances, device_instances<1, 4>{});

    // prefetch 2, ksplit factor: 4
    add_device_operation_instances(instances, device_instances<2, 4>{});

    // prefetch 1, ksplit factor: 8
    add_device_operation_instances(instances, device_instances<1, 8>{});

    // prefetch 2, ksplit factor: 8
    add_device_operation_instances(instances, device_instances<2, 8>{});

    // prefetch 1, ksplit factor: 16
    add_device_operation_instances(instances, device_instances<1, 16>{});

    // prefetch 2, ksplit factor: 16
    add_device_operation_instances(instances, device_instances<2, 16>{});
}

} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
