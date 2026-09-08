// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"

namespace ck_tile {

template <typename Problem,
          typename Policy,
          bool ALdsDirectLoad = false,
          bool BLdsDirectLoad = false>
struct ConvIgemmPipelineAGmemBGmemCRegV1
{
    using ADataType = remove_cvref_t<typename Problem::ADataType>;
    using BDataType = remove_cvref_t<typename Problem::BDataType>;
    using CDataType = remove_cvref_t<typename Problem::CDataType>;

    using ALayout = remove_cvref_t<typename Problem::ALayout>;
    using BLayout = remove_cvref_t<typename Problem::BLayout>;
    using CLayout = remove_cvref_t<typename Problem::CLayout>;

    using AElementwiseOp = typename Problem::AElementwiseOp;
    using BElementwiseOp = typename Problem::BElementwiseOp;
    using CElementwiseOp = typename Problem::CElementwiseOp;

    static constexpr index_t NDimSpatial = Problem::NDimSpatial;

    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t BlockSize = Problem::BlockSize;

    static constexpr index_t NumPrefetch = Problem::NumPrefetch;

    static constexpr index_t AVectorLength = Problem::AGmemLoadVectorLength;
    static constexpr index_t BVectorLength = Problem::BGmemLoadVectorLength;
    static constexpr index_t CVectorLength = Problem::CGmemStoreVectorLength;

    CK_TILE_HOST_DEVICE static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % NumPrefetch == 0;
    }

    CK_TILE_HOST_DEVICE static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / NumPrefetch) > 1;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetSmemByteSize()
    {
        return Policy::template GetAlignedSmemByteSize<Problem>();
    }

    template <typename ACopyDramWindow,
              typename BCopyDramWindow,
              typename AElementwiseOp,
              typename BElementwiseOp,
              bool ALdsDirectLoad_ = ALdsDirectLoad,
              bool BLdsDirectLoad_ = BLdsDirectLoad,
              typename std::enable_if<
                  std::is_same_v<bool_constant<ALdsDirectLoad_>, bool_constant<false>> &&
                      std::is_same_v<bool_constant<BLdsDirectLoad_>, bool_constant<false>>,
                  bool>::type = false>
    CK_TILE_DEVICE auto operator()(const ACopyDramWindow& a_copy_dram_window_,
                                   const AElementwiseOp& a_element_op,
                                   const BCopyDramWindow& b_copy_dram_window_,
                                   const BElementwiseOp& b_element_op,
                                   index_t num_loop,
                                   void* p_smem) const
    {
        auto a_copy_dram_window =
            make_tile_window(a_copy_dram_window_.get_bottom_tensor_view(),
                             make_tuple(number<1>{}, number<MPerBlock>{}, number<KPerBlock>{}),
                             a_copy_dram_window_.get_window_origin(),
                             Policy::template MakeADramTileDistribution<Problem>());

        auto b_copy_dram_window =
            make_tile_window(b_copy_dram_window_.get_bottom_tensor_view(),
                             make_tuple(number<1>{}, number<NPerBlock>{}, number<KPerBlock>{}),
                             b_copy_dram_window_.get_window_origin(),
                             Policy::template MakeBDramTileDistribution<Problem>());

        constexpr auto a_copy_dram_window_step = make_multi_index(0, 0, KPerBlock);
        constexpr auto b_copy_dram_window_step = make_multi_index(0, 0, KPerBlock);

        // A matrix in LDS
        constexpr auto a_copy_lds_block_desc =
            Policy::template MakeALdsCopyBlockDescriptor<Problem>();

        constexpr auto a_gemm_lds_block_desc =
            Policy::template MakeALdsGemmBlockDescriptor<Problem>();

        // B matrix in LDS
        constexpr auto b_copy_lds_block_desc =
            Policy::template MakeBLdsCopyBlockDescriptor<Problem>();

        constexpr auto b_gemm_lds_block_desc =
            Policy::template MakeBLdsGemmBlockDescriptor<Problem>();

        constexpr auto a_lds_space_size_aligned = Policy::template GetAlignedSmemSizeA<Problem>();
        constexpr auto b_lds_space_size_aligned = Policy::template GetAlignedSmemSizeB<Problem>();

        constexpr auto a_lds_bufs_elem_offset = 0;
        constexpr auto b_lds_bufs_elem_offset = a_lds_space_size_aligned * NumPrefetch;

        // A LDS tile for store
        auto a_copy_lds_windows = lds_utils::AllocateLdsWindows<ADataType, NumPrefetch>(
            p_smem,
            a_lds_space_size_aligned,
            a_lds_bufs_elem_offset,
            KPerBlock,
            make_tuple(number<1>{}, number<MPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0, 0),
            a_copy_lds_block_desc,
            a_copy_dram_window.get_tile_distribution());

        // B LDS tile for store
        auto b_copy_lds_windows = lds_utils::AllocateLdsWindows<BDataType, NumPrefetch>(
            p_smem,
            b_lds_space_size_aligned,
            b_lds_bufs_elem_offset,
            KPerBlock,
            make_tuple(number<1>{}, number<NPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0, 0),
            b_copy_lds_block_desc,
            b_copy_dram_window.get_tile_distribution());

        // A LDS tile for load
        auto a_gemm_lds_windows = lds_utils::AllocateLdsWindows<ADataType, NumPrefetch>(
            p_smem,
            a_lds_space_size_aligned,
            a_lds_bufs_elem_offset,
            KPerBlock,
            make_tuple(number<MPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0),
            a_gemm_lds_block_desc);

        // B LDS tile for load
        auto b_gemm_lds_windows = lds_utils::AllocateLdsWindows<BDataType, NumPrefetch>(
            p_smem,
            b_lds_space_size_aligned,
            b_lds_bufs_elem_offset,
            KPerBlock,
            make_tuple(number<NPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0),
            b_gemm_lds_block_desc);

        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        statically_indexed_array<decltype(load_tile(a_copy_dram_window)), NumPrefetch>
            a_tmp_buffers;
        statically_indexed_array<decltype(load_tile(b_copy_dram_window)), NumPrefetch>
            b_tmp_buffers;

        auto c_block_tensor = blockwise_gemm.MakeCBlockTile();

        // initialize C
        tile_elementwise_inout([](auto& c) { c = 0; }, c_block_tensor);

        // Load 0 ~ NumPrefetch - 2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(a_tmp_buffers(number<i>{}), a_copy_dram_window);
            load_tile_by_inline_asm(b_tmp_buffers(number<i>{}), b_copy_dram_window);

            __builtin_amdgcn_sched_barrier(0);

            move_tile_window(a_copy_dram_window, a_copy_dram_window_step);
            move_tile_window(b_copy_dram_window, b_copy_dram_window_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumPrefetch - 1
        load_tile_by_inline_asm(a_tmp_buffers(number<NumPrefetch - 1>{}), a_copy_dram_window);
        load_tile_by_inline_asm(b_tmp_buffers(number<NumPrefetch - 1>{}), b_copy_dram_window);
        __builtin_amdgcn_sched_barrier(0);

        // main body
        if constexpr(Problem::HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumPrefetch - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence((a_copy_dram_window.get_num_of_access() +
                                       b_copy_dram_window.get_num_of_access()) *
                                      (NumPrefetch - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    tile_elementwise_inout(
                        a_element_op, a_tmp_buffers(number<i>{}), a_tmp_buffers(number<i>{}));
                    tile_elementwise_inout(
                        b_element_op, b_tmp_buffers(number<i>{}), b_tmp_buffers(number<i>{}));

                    // Write to LDS
                    store_tile(a_copy_lds_windows.at(number<i>{}), a_tmp_buffers[number<i>{}]);
                    store_tile(b_copy_lds_windows.at(number<i>{}), b_tmp_buffers[number<i>{}]);

                    __builtin_amdgcn_sched_barrier(0);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Read i
                    const auto a_warp_tensors =
                        blockwise_gemm.LdsLoadA(a_gemm_lds_windows.at(number<i>{}));
                    const auto b_warp_tensors =
                        blockwise_gemm.LdsLoadB(b_gemm_lds_windows.at(number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    move_tile_window(a_copy_dram_window, a_copy_dram_window_step);
                    move_tile_window(b_copy_dram_window, b_copy_dram_window_step);
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // Mmac i
                    blockwise_gemm(c_block_tensor, a_warp_tensors, b_warp_tensors);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Load i+2
                    load_tile_by_inline_asm(a_tmp_buffers(number<i>{}), a_copy_dram_window);
                    load_tile_by_inline_asm(b_tmp_buffers(number<i>{}), b_copy_dram_window);
                    __builtin_amdgcn_sched_barrier(0);
                });

                loop += NumPrefetch;

            } while(loop < num_loop - NumPrefetch);
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto i) {
                // Wait num_loop-i-NumPrefetch
                __builtin_amdgcn_sched_barrier(0);
                buffer_load_fence((a_copy_dram_window.get_num_of_access() +
                                   b_copy_dram_window.get_num_of_access()) *
                                  (NumPrefetch - 1 - i));
                __builtin_amdgcn_sched_barrier(0);

                tile_elementwise_inout(
                    a_element_op, a_tmp_buffers(number<i>{}), a_tmp_buffers(number<i>{}));
                tile_elementwise_inout(
                    b_element_op, b_tmp_buffers(number<i>{}), b_tmp_buffers(number<i>{}));

                // Write to LDS
                store_tile(a_copy_lds_windows.at(number<i>{}), a_tmp_buffers[number<i>{}]);
                store_tile(b_copy_lds_windows.at(number<i>{}), b_tmp_buffers[number<i>{}]);
                __builtin_amdgcn_sched_barrier(0);

                // Sync with other waves to avoid data hazard
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // Read num_loop-i-NumPrefetch
                const auto a_warp_tensors =
                    blockwise_gemm.LdsLoadA(a_gemm_lds_windows.at(number<i>{}));
                const auto b_warp_tensors =
                    blockwise_gemm.LdsLoadB(b_gemm_lds_windows.at(number<i>{}));
                __builtin_amdgcn_sched_barrier(0);

                // Mmac num_loop-i-NumPrefetch-2
                blockwise_gemm(c_block_tensor, a_warp_tensors, b_warp_tensors);
                __builtin_amdgcn_sched_barrier(0);
            });
        }

        return c_block_tensor;
    }

    template <typename ACopyDramWindow,
              typename BCopyDramWindow,
              typename AElementwiseOp,
              typename BElementwiseOp,
              bool ALdsDirectLoad_ = ALdsDirectLoad,
              bool BLdsDirectLoad_ = BLdsDirectLoad,
              typename std::enable_if<
                  std::is_same_v<bool_constant<ALdsDirectLoad_>, bool_constant<true>> &&
                      std::is_same_v<bool_constant<BLdsDirectLoad_>, bool_constant<true>>,
                  bool>::type = false>
    CK_TILE_DEVICE auto operator()(const ACopyDramWindow& a_copy_dram_window_,
                                   const AElementwiseOp& /*a_element_op*/,
                                   const BCopyDramWindow& b_copy_dram_window_,
                                   const BElementwiseOp& /*b_element_op*/,
                                   index_t num_loop,
                                   void* p_smem) const
    {
        auto a_copy_dram_window =
            make_tile_window(a_copy_dram_window_.get_bottom_tensor_view(),
                             make_tuple(number<1>{}, number<MPerBlock>{}, number<KPerBlock>{}),
                             a_copy_dram_window_.get_window_origin(),
                             Policy::template MakeADramTileDistribution<Problem>());
        a_copy_dram_window.init_raw();

        auto b_copy_dram_window =
            make_tile_window(b_copy_dram_window_.get_bottom_tensor_view(),
                             make_tuple(number<1>{}, number<NPerBlock>{}, number<KPerBlock>{}),
                             b_copy_dram_window_.get_window_origin(),
                             Policy::template MakeBDramTileDistribution<Problem>());
        b_copy_dram_window.init_raw();

        constexpr auto a_copy_dram_window_step = make_multi_index(0, 0, KPerBlock);
        constexpr auto b_copy_dram_window_step = make_multi_index(0, 0, KPerBlock);

        // A matrix in LDS
        constexpr auto a_copy_lds_block_desc =
            Policy::template MakeALdsAsyncCopyBlockDescriptor<Problem>();

        constexpr auto a_gemm_lds_block_desc =
            Policy::template MakeALdsGemmBlockDescriptor<Problem>();

        // B matrix in LDS
        constexpr auto b_copy_lds_block_desc =
            Policy::template MakeBLdsAsyncCopyBlockDescriptor<Problem>();

        constexpr auto b_gemm_lds_block_desc =
            Policy::template MakeBLdsGemmBlockDescriptor<Problem>();

        constexpr auto a_lds_space_size_aligned = Policy::template GetAlignedSmemSizeA<Problem>();
        constexpr auto b_lds_space_size_aligned = Policy::template GetAlignedSmemSizeB<Problem>();

        constexpr auto a_lds_bufs_elem_offset = 0;
        constexpr auto b_lds_bufs_elem_offset = a_lds_space_size_aligned * NumPrefetch;

        // A LDS tile for store
        auto a_copy_lds_windows = lds_utils::AllocateLdsWindows<ADataType, NumPrefetch>(
            p_smem,
            a_lds_space_size_aligned,
            a_lds_bufs_elem_offset,
            KPerBlock,
            a_copy_lds_block_desc.get_lengths(),
            make_multi_index(0, 0, 0),
            a_copy_lds_block_desc);

        // B LDS tile for store
        auto b_copy_lds_windows = lds_utils::AllocateLdsWindows<BDataType, NumPrefetch>(
            p_smem,
            b_lds_space_size_aligned,
            b_lds_bufs_elem_offset,
            KPerBlock,
            b_copy_lds_block_desc.get_lengths(),
            make_multi_index(0, 0, 0),
            b_copy_lds_block_desc);

        // A LDS tile for load
        auto a_gemm_lds_windows = lds_utils::AllocateLdsWindows<ADataType, NumPrefetch>(
            p_smem,
            a_lds_space_size_aligned,
            a_lds_bufs_elem_offset,
            KPerBlock,
            make_tuple(number<MPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0),
            a_gemm_lds_block_desc);

        // B LDS tile for load
        auto b_gemm_lds_windows = lds_utils::AllocateLdsWindows<BDataType, NumPrefetch>(
            p_smem,
            b_lds_space_size_aligned,
            b_lds_bufs_elem_offset,
            KPerBlock,
            make_tuple(number<NPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0),
            b_gemm_lds_block_desc);

        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto c_block_tensor = blockwise_gemm.MakeCBlockTile();

        // initialize C
        tile_elementwise_inout([](auto& c) { c = 0; }, c_block_tensor);

        // Load 0 ~ NumPrefetch - 2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            async_load_tile_by_inline_asm(a_copy_lds_windows(number<i>{}), a_copy_dram_window);
            async_load_tile_by_inline_asm(b_copy_lds_windows(number<i>{}), b_copy_dram_window);

            __builtin_amdgcn_sched_barrier(0);

            move_tile_window(a_copy_dram_window, a_copy_dram_window_step);
            move_tile_window(b_copy_dram_window, b_copy_dram_window_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumPrefetch - 1
        async_load_tile_by_inline_asm(a_copy_lds_windows(number<NumPrefetch - 1>{}),
                                      a_copy_dram_window);
        async_load_tile_by_inline_asm(b_copy_lds_windows(number<NumPrefetch - 1>{}),
                                      b_copy_dram_window);
        __builtin_amdgcn_sched_barrier(0);

        // main body
        if constexpr(Problem::HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumPrefetch - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    async_load_fence((a_copy_dram_window.get_num_of_access() +
                                      b_copy_dram_window.get_num_of_access()) *
                                     (NumPrefetch - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Read i
                    const auto a_warp_tensors =
                        blockwise_gemm.LdsLoadA(a_gemm_lds_windows.at(number<i>{}));
                    const auto b_warp_tensors =
                        blockwise_gemm.LdsLoadB(b_gemm_lds_windows.at(number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    move_tile_window(a_copy_dram_window, a_copy_dram_window_step);
                    move_tile_window(b_copy_dram_window, b_copy_dram_window_step);
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // Mmac i
                    blockwise_gemm(c_block_tensor, a_warp_tensors, b_warp_tensors);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Load i+2
                    async_load_tile_by_inline_asm(a_copy_lds_windows(number<i>{}),
                                                  a_copy_dram_window);
                    async_load_tile_by_inline_asm(b_copy_lds_windows(number<i>{}),
                                                  b_copy_dram_window);
                    __builtin_amdgcn_sched_barrier(0);
                });

                loop += NumPrefetch;

            } while(loop < num_loop - NumPrefetch);
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto i) {
                // Wait num_loop-i-NumPrefetch
                __builtin_amdgcn_sched_barrier(0);
                async_load_fence((a_copy_dram_window.get_num_of_access() +
                                  b_copy_dram_window.get_num_of_access()) *
                                 (NumPrefetch - 1 - i));
                __builtin_amdgcn_sched_barrier(0);

                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // Read num_loop-i-NumPrefetch
                const auto a_warp_tensors =
                    blockwise_gemm.LdsLoadA(a_gemm_lds_windows.at(number<i>{}));
                const auto b_warp_tensors =
                    blockwise_gemm.LdsLoadB(b_gemm_lds_windows.at(number<i>{}));
                __builtin_amdgcn_sched_barrier(0);

                // Mmac num_loop-i-NumPrefetch-2
                blockwise_gemm(c_block_tensor, a_warp_tensors, b_warp_tensors);
                __builtin_amdgcn_sched_barrier(0);
            });
        }

        return c_block_tensor;
    }
};

} // namespace ck_tile
