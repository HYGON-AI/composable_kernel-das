// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

namespace ck_tile {

template <typename BlockShape_,
          index_t IntermediateTilesPerBlock_ = 1,
          bool DebugWriterCount_ = false>
struct FusedMoeGemmTilePartitioner_Linear
{
    //  FusedMoeGemmShape
    using BlockShape = ck_tile::remove_cvref_t<BlockShape_>;
    static constexpr index_t IntermediateTilesPerBlock = IntermediateTilesPerBlock_;
    static constexpr bool DebugWriterCount = DebugWriterCount_;
    static_assert(IntermediateTilesPerBlock > 0);

    static constexpr const char* name = "lin";

    CK_TILE_DEVICE auto operator()(ck_tile::index_t /*num_sorted_tiles*/,
                                   ck_tile::index_t /*intermediate_size*/)
    {
        index_t i_n = blockIdx.x;
        index_t i_m = blockIdx.y;

        return ck_tile::make_tuple(i_m, i_n);
    }

    CK_TILE_HOST static constexpr auto GridSize(index_t max_tokens, index_t intermediate_size, int max_num_m_block = 0)
    {
        // TODO: this may need tuning
        index_t ms = ck_tile::integer_divide_ceil(max_tokens, BlockShape::Block_M0);
        index_t ns = ck_tile::integer_divide_ceil(
            intermediate_size, BlockShape::Block_N0 * IntermediateTilesPerBlock);
        if (max_num_m_block > 0)
        {
            // 减少小token_num时启动的无效block数量
            ms = std::min(max_num_m_block, static_cast<int>(ms));
        }
        return dim3(ns, ms, 1);
    }
};
} // namespace ck_tile
