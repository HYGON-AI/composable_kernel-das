// SPDX-License-Identifier: MIT
// Copyright (c) 2024, Advanced Micro Devices, Inc. All rights reserved.
// Modified by Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"

namespace ck_tile {

enum class FusedMoeGemmWeightPermuteEnum
{
    // permute_b_n0_k0_n1_k1_n2_k2 = 0, // 0,1,4,2,5,3,6
    // permute_b_n0_n1_k0_k1_n2_k2 = 1, // 0,1,2,4,5,3,6
    no_permute          = 0,
    permute_b    =  1, //e, interm_block_num, kiter, nwaves, kwaves, nrepeat, ninterleave, krepeat, klane, nlane, nvec, kvec
    permute_bd    = 2,
};

template <bool IsGateOnly_,
          bool UseSmoothQuant_,
          index_t OAtomic_, // 0-no atomic, 1-atomic-pk-f16/bf16, 2-atomic-f32
          typename GmemLoadVectorLengths_,
          typename SmemStoreVectorLengths_,
          typename SmemLoadVectorLengths_,
          index_t OGmemStoreVectorLength_,
          index_t Gemm0NInterleave_,
          index_t Gemm1NInterleave_,
          FusedMoeGemmWeightPermuteEnum PermuteEnum_ =
              FusedMoeGemmWeightPermuteEnum::no_permute,
          bool IsSwizzled_          = true,
          bool PadHiddenSize_       = false,
          bool PadIntermediateSize_ = false,
          bool PipeInterleave_      = true>
struct FusedMoeGemmTraits
{
    using GmemLoadVectorLengths  = remove_cvref_t<GmemLoadVectorLengths_>;
    using SmemStoreVectorLengths = remove_cvref_t<SmemStoreVectorLengths_>;
    using SmemLoadVectorLengths  = remove_cvref_t<SmemLoadVectorLengths_>;

    // Gate+Up or Gate only
    static constexpr bool IsGateOnly                           = IsGateOnly_;
    static constexpr bool UseSmoothQuant                       = UseSmoothQuant_;
    static constexpr index_t OAtomic                           = OAtomic_;
    static constexpr FusedMoeGemmWeightPermuteEnum PermuteEnum = PermuteEnum_;
    static constexpr bool PadHiddenSize                        = PadHiddenSize_;
    static constexpr bool PadIntermediateSize                  = PadIntermediateSize_;
    static constexpr bool PipeInterleave                       = PipeInterleave_;
    static constexpr bool IsSwizzled                           = IsSwizzled_;

    // Global load vector length
    static constexpr index_t AGmemLoadVectorLength = GmemLoadVectorLengths::at(number<0>{}); // 4
    static constexpr index_t GGmemLoadVectorLength = GmemLoadVectorLengths::at(number<1>{}); // 8
    static constexpr index_t UGmemLoadVectorLength =
        GmemLoadVectorLengths::at(number<2>{}); // 8 only for gate_up, gate_only will be meaningless
    static constexpr index_t DGmemLoadVectorLength = GmemLoadVectorLengths::at(number<3>{}); // 8

    // smem load vector length
    static constexpr index_t ASmemLoadVectorLength = SmemLoadVectorLengths::at(number<0>{}); // 8
    static constexpr index_t GSmemLoadVectorLength =
        SmemLoadVectorLengths::at(number<1>{}); // 8 not used
    static constexpr index_t USmemLoadVectorLength = SmemLoadVectorLengths::at(number<2>{}); // 8
    static constexpr index_t DSmemLoadVectorLength = SmemLoadVectorLengths::at(number<3>{}); // 1

    // smem store vector length
    static constexpr index_t BridgeSmemStoreVectorLength =
        SmemStoreVectorLengths::at(number<0>{}); // must match with mmac 64B/datatype

    static constexpr index_t Gemm0NInterleave = Gemm0NInterleave_;
    static constexpr index_t Gemm1NInterleave = Gemm1NInterleave_;

    static constexpr index_t OGmemStoreVectorLength = OGmemStoreVectorLength_;
};

// Note: this need to be a bit mask
enum class FusedMoeGemmPipelineSequencerEnum
{
    SLD_A = 1 << 0, // shared load a
    SLD_B = 1 << 1,
    GLD_A = 1 << 2, // global load a
    GLD_B = 1 << 3,
    SST_A = 1 << 4, // shared store a
    SST_B = 1 << 5,
    GST_O = 1 << 6, // global store out
};
} // namespace ck_tile
