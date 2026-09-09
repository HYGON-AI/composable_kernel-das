// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <cstdlib>

#include "ck/ck.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_data_specialization.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/impl/device_grouped_conv_bwd_data_mmac.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"

namespace ck {
namespace tensor_operation {
namespace device {
namespace instance {

using BF16 = ck::bhalf_t;
using F16  = ck::half_t;
using F32  = float;

using Empty_Tuple = ck::Tuple<>;

template <ck::index_t... Is>
using S = ck::Sequence<Is...>;

using NGCHW    = ck::tensor_layout::convolution::NGCHW;
using GKCYXc32 = ck::tensor_layout::convolution::GKCYXc32;
using NGKHWk32 = ck::tensor_layout::convolution::NGKHWk32;

using PassThrough = ck::tensor_operation::element_wise::PassThrough;

static constexpr auto ConvBwdDataDefault =
    ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::Default;

static constexpr auto ConvBwdData1x1S1P0 =
    ck::tensor_operation::device::ConvolutionBackwardDataSpecialization::Filter1x1Stride1Pad0;

static constexpr auto GemmMNKPadding = ck::tensor_operation::device::GemmSpecialization::MNKPadding;

// for GNHWK/GKYXC/GNHWC or NHWGK/GKYXC/NHWGC
template <typename ALayout,
          typename BLayout,
          typename CLayout,
          typename ADataType,
          typename BDataType,
          typename CDataType,
          ConvolutionBackwardDataSpecialization ConvBwdDataSpec,
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
using DeviceOp = DeviceGroupedConvBwdData_Mmac<2,
                                               ALayout,
                                               BLayout,
                                               CLayout,
                                               ADataType,
                                               BDataType,
                                               F32, // AccDataType
                                               CDataType,
                                               PassThrough,
                                               PassThrough,
                                               PassThrough,
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
                                               S<1, 0, 2>,
                                               S<1, 0, 2>,
                                               2, // ABlockTransferSrcVectorDim (GemmK)
                                               ABlockTransferSrcScalarPerVector,
                                               ABlockTransferDstScalarPerVector_K1,
                                               ABlockLdsAddExtraM,
                                               BBlockTransferThreadClusterLengths_K0_N_K1,
                                               S<0, 2, 1>,
                                               S<0, 2, 1>,
                                               1, // BBlockTransferSrcVectorDim (GemmN)
                                               BBlockTransferSrcScalarPerVector,
                                               BBlockTransferDstScalarPerVector_K1,
                                               BBlockLdsAddExtraN,
                                               NumGemmKPrefetchStage>;
} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
