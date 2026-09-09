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
template <
    ConvolutionForwardSpecialization ConvFwdSpec,
    ck::index_t BlockSize,
    ck::index_t MPerBlock,
    ck::index_t NPerBlock,
    ck::index_t KPerBlock,
    ck::index_t AK1,
    ck::index_t BK1,
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
    ck::index_t CShuffleMMmacPerWavePerShuffle,
    ck::index_t CShuffleNMmacPerWavePerShuffle,
    typename CBlockTransferClusterLengths_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac,
    ck::index_t CBlockTransferScalarPerVector_NWaveNPerMmac,
    ck::index_t NumGemmKPrefetchStage>
using DeviceOpF32 = DeviceOp<
    NHWGC,
    GKYXC,
    NHWGK,
    F32,
    F32,
    F32,
    ConvFwdSpec,
    BlockSize,
    MPerBlock,
    NPerBlock,
    KPerBlock,
    AK1,
    BK1,
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
    CShuffleMMmacPerWavePerShuffle,
    CShuffleNMmacPerWavePerShuffle,
    CBlockTransferClusterLengths_MBlock_MMmacPerWave_MWaveMPerMmac_NBlock_NMmacPerWave_NWaveNPerMmac,
    CBlockTransferScalarPerVector_NWaveNPerMmac,
    NumGemmKPrefetchStage>;

// for first layer
using device_instances = std::tuple<
    // clang-format off
    // K: 4x4
    DeviceOpF32<ConvFwdDefault, 256, 256, 128, 16, 4, 4, 16, 16, 8, 4, S<4, 64, 1>, 1, 4, true, S<4, 64, 1>, 1, 4, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 256, 16, 4, 4, 16, 16, 4, 8, S<4, 64, 1>, 1, 4, true, S<4, 64, 1>, 1, 4, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 128, 16, 4, 4, 16, 16, 4, 4, S<4, 64, 1>, 1, 4, true, S<4, 64, 1>, 1, 4, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 64,  16, 4, 4, 16, 16, 4, 2, S<4, 64, 1>, 1, 4, true, S<4, 64, 1>, 1, 4, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 64,  128, 16, 4, 4, 16, 16, 2, 4, S<4, 64, 1>, 1, 4, true, S<4, 64, 1>, 1, 4, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 32,  16, 4, 4, 16, 16, 4, 1, S<4, 64, 1>, 1, 4, true, S<4, 32, 2>, 1, 2, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,

    // K: 4x2
    DeviceOpF32<ConvFwdDefault, 256, 256, 128, 8, 2, 2, 16, 16, 8, 4, S<4, 64, 1>, 1, 2, true, S<4, 64, 1>, 1, 2, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 256, 8, 2, 2, 16, 16, 4, 8, S<4, 64, 1>, 1, 2, true, S<4, 64, 1>, 1, 2, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 128, 8, 2, 2, 16, 16, 4, 4, S<4, 64, 1>, 1, 2, true, S<4, 64, 1>, 1, 2, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 64,  8, 2, 2, 16, 16, 4, 2, S<4, 64, 1>, 1, 2, true, S<4, 64, 1>, 1, 2, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 64,  128, 8, 2, 2, 16, 16, 2, 4, S<4, 64, 1>, 1, 2, true, S<4, 64, 1>, 1, 2, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>,
    DeviceOpF32<ConvFwdDefault, 256, 128, 32,  8, 2, 2, 16, 16, 4, 1, S<4, 64, 1>, 1, 2, true, S<4, 32, 2>, 1, 1, true, 1, 1, S<1, 1, 32, 1, 1, 8>, 4, 1>
    // clang-format on
    >;

void add_device_grouped_conv2d_fwd_mmac_nhwgc_gkyxc_nhwgk_f32_oddc_instances(
    std::vector<std::unique_ptr<DeviceGroupedConvFwd<2,
                                                     NHWGC,
                                                     GKYXC,
                                                     NHWGK,
                                                     F32,
                                                     F32,
                                                     F32,
                                                     PassThrough,
                                                     PassThrough,
                                                     PassThrough>>>& instances)
{
    // prefetch 1
    add_device_operation_instances(instances, device_instances{});
}

} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
