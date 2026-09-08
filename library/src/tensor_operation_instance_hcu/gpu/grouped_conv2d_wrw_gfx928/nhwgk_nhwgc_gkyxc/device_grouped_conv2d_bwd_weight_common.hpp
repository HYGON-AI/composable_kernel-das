// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

#include <cstdlib>

#include "ck/ck.hpp"
#include "ck/tensor_operation/gpu/device/tensor_layout.hpp"
#include "ck/tensor_operation/gpu/device/convolution_backward_weight_specialization.hpp"
#include "ck/tensor_operation/gpu/device/gemm_specialization.hpp"
#include "ck/tensor_operation/gpu/device/impl/device_grouped_conv_bwd_weight_mmac.hpp"
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

using NHWGC = ck::tensor_layout::convolution::NHWGC;
using GNHWC = ck::tensor_layout::convolution::GNHWC;
using NGCHW = ck::tensor_layout::convolution::NGCHW;
using GNCHW = ck::tensor_layout::convolution::GNCHW;

using GKYXC = ck::tensor_layout::convolution::GKYXC;
using GKCYX = ck::tensor_layout::convolution::GKCYX;

using NHWGK = ck::tensor_layout::convolution::NHWGK;
using GNHWK = ck::tensor_layout::convolution::GNHWK;
using NGKHW = ck::tensor_layout::convolution::NGKHW;
using GNKHW = ck::tensor_layout::convolution::GNKHW;

using PassThrough = ck::tensor_operation::element_wise::PassThrough;

static constexpr auto ConvBwdWeightDefault =
    ck::tensor_operation::device::ConvolutionBackwardWeightSpecialization::Default;

static constexpr auto ConvBwdWeight1x1P0 =
    ck::tensor_operation::device::ConvolutionBackwardWeightSpecialization::Filter1x1Pad0;

static constexpr auto ConvBwdWeight1x1S1P0 =
    ck::tensor_operation::device::ConvolutionBackwardWeightSpecialization::Filter1x1Stride1Pad0;

static constexpr auto ConvBwdWeightOddC =
    ck::tensor_operation::device::ConvolutionBackwardWeightSpecialization::OddC;

static constexpr auto GemmMNKPadding = ck::tensor_operation::device::GemmSpecialization::MNKPadding;

template <typename ADataType,
          typename BDataType,
          typename CDataType,
          ConvolutionBackwardWeightSpecialization ConvBwdWeightSpec,
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
          ck::index_t GemmKSplitFactor = 1>
using DeviceOp = DeviceGroupedConvBwdWeight_Mmac<2,
                                                 NHWGK,
                                                 NHWGC,
                                                 GKYXC,
                                                 ADataType,
                                                 BDataType,
                                                 F32, // AccDataType
                                                 CDataType,
                                                 PassThrough,
                                                 PassThrough,
                                                 PassThrough,
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
                                                 S<0, 3, 1, 2>,
                                                 S<0, 2, 1, 3>,
                                                 2, // ABlockTransferSrcVectorDim (GemmM)
                                                 ABlockTransferSrcScalarPerVector,
                                                 ABlockTransferDstScalarPerVector_K1,
                                                 ABlockLdsAddExtraM,
                                                 BBlockTransferThreadClusterLengths_B_K0_N_K1,
                                                 S<0, 3, 1, 2>,
                                                 S<0, 2, 1, 3>,
                                                 2, // BBlockTransferSrcVectorDim (GemmN)
                                                 BBlockTransferSrcScalarPerVector,
                                                 BBlockTransferDstScalarPerVector_K1,
                                                 BBlockLdsAddExtraN,
                                                 NumGemmKPrefetchStage,
                                                 GemmKSplitFactor>;
} // namespace instance
} // namespace device
} // namespace tensor_operation
} // namespace ck
