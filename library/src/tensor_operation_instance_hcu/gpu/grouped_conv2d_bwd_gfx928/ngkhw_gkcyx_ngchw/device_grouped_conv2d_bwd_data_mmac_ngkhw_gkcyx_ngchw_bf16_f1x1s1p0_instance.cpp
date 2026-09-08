// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#include <memory>
#include <tuple>

#include "ck/library/tensor_operation_instance_hcu/add_device_operation_instance.hpp"
#include "device_grouped_conv2d_bwd_data_common.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

template <ConvolutionBackwardDataSpecialization ConvBwdDataSpec,
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
using DeviceOpBF16 = DeviceOp<NGKHW,
                              GKCYX,
                              NGCHW,
                              BF16,
                              BF16,
                              BF16,
                              ConvBwdDataSpec,
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

template <ck::index_t NumGemmKPrefetchStage = 1>
using device_instances = std::tuple<
    // clang-format off
    // 4-wave
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 256, 128, 4, 8, 16, 16, 8, 4, S<4, 32, 2>, 8, 8, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 256, 128, 4, 8, 16, 16, 8, 4, S<4, 64, 1>, 4, 8, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 256, 128, 4, 8, 16, 16, 8, 4, S<4, 64, 1>, 1, 8, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 256, 4, 8, 16, 16, 4, 8, S<4, 16, 4>, 8, 2, true, S<4, 32, 2>, 8, 4, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 256, 4, 8, 16, 16, 4, 8, S<4, 32, 2>, 4, 4, true, S<4, 32, 2>, 8, 4, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 256, 4, 8, 16, 16, 4, 8, S<4, 64, 1>, 1, 8, true, S<4, 32, 2>, 8, 4, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<4, 16, 4>, 8, 2, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<4, 32, 2>, 4, 4, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 128, 4, 8, 16, 16, 4, 4, S<4, 64, 1>, 1, 8, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 64,  4, 8, 16, 16, 4, 2, S<4, 16, 4>, 8, 2, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 64,  4, 8, 16, 16, 4, 2, S<4, 32, 2>, 4, 4, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 64,  4, 8, 16, 16, 4, 2, S<4, 64, 1>, 2, 8, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 64,  4, 8, 16, 16, 4, 2, S<4, 64, 1>, 1, 8, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 64, 128,  4, 8, 16, 16, 2, 4, S<4, 8,  8>, 8, 1, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 64, 128,  4, 8, 16, 16, 2, 4, S<4, 16, 4>, 4, 2, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 64, 128,  4, 8, 16, 16, 2, 4, S<4, 64, 1>, 1, 8, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 32,  4, 8, 16, 16, 4, 1, S<4, 16, 4>, 8, 2, true, S<4, 8, 8>, 4, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 32,  4, 8, 16, 16, 4, 1, S<4, 32, 2>, 4, 4, true, S<4, 8, 8>, 4, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 128, 32,  4, 8, 16, 16, 4, 1, S<4, 64, 1>, 1, 8, true, S<4, 8, 8>, 4, 1, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 32, 128,  4, 8, 16, 16, 1, 4, S<4, 8,  8>, 4, 1, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 32, 128,  4, 8, 16, 16, 1, 4, S<4, 32, 2>, 1, 4, true, S<4, 16, 4>, 8, 2, true, NumGemmKPrefetchStage>,

    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 64,  64,  4, 8, 16, 16, 2, 2, S<4, 8,  8>, 8, 1, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 64,  64,  4, 8, 16, 16, 2, 2, S<4, 16, 4>, 4, 2, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>,
    DeviceOpBF16<ConvBwdData1x1S1P0, 256, 64,  64,  4, 8, 16, 16, 2, 2, S<4, 64, 1>, 1, 8, true, S<4, 8, 8>, 8, 1, true, NumGemmKPrefetchStage>
    // clang-format on
    >;

void add_device_grouped_conv2d_bwd_data_mmac_ngkhw_gkcyx_ngchw_bf16_f1x1s1p0_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvBwdData<2,
                                                         NGKHW,
                                                         GKCYX,
                                                         NGCHW,
                                                         BF16,
                                                         BF16,
                                                         BF16,
                                                         PassThrough,
                                                         PassThrough,
                                                         PassThrough>>>& instances)
{
    // prefetch 1
    add_device_operation_instances(instances, device_instances<1>{});

    // prefetch 2
    add_device_operation_instances(instances, device_instances<1>{});
}

} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
