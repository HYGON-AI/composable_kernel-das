// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_>
struct FusedConvIgemmPipelineMlsWaspAgmemBgmemCregV1
{
    using Problem = remove_cvref_t<Problem_>;
    using Policy  = remove_cvref_t<Policy_>;

    static constexpr index_t NumLdsStages = Problem::NumLdsStages;
    static constexpr index_t FilterUnroll = Problem::FilterUnroll;

    static_assert(FilterUnroll == 1, "Non-1x1 conv is not supported by this pipeline");

    // compute warp groups
    static constexpr index_t MWGs = Problem::MWGs;
    static constexpr index_t NWGs = Problem::NWGs;

    static constexpr bool is_input_shared = Problem::is_input_shared;

    CK_TILE_HOST static bool IsSupported(const index_t num_loop)
    {
        return (num_loop % NumLdsStages) == 0;
    }

    CK_TILE_HOST static bool CalculateHasMainLoop(const index_t num_loop)
    {
        return (num_loop / NumLdsStages) > 1;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return Policy::template GetLdsByteSize<Problem>();
    }

    CK_TILE_DEVICE static bool IsProducerWG()
    {
        return get_sub_warpgroup_id(Problem::SubWGSize) == 0;
    }

    CK_TILE_DEVICE static bool IsMajorComputeWG()
    {
        return get_sub_warpgroup_id(Problem::SubWGSize) == 1;
    }

    CK_TILE_DEVICE static bool IsMinorComputeWG()
    {
        return get_sub_warpgroup_id(Problem::SubWGSize) == 2;
    }

    // producer pipeline
    template <typename SharedWGDramWindow,
              typename PrivateWGDramWindowMajor,
              typename PrivateWGDramWindowMinor,
              typename SharedWGLdsWindows,
              typename PrivateWGLdsWindowsMajor,
              typename PrivateWGLdsWindowsMinor,
              bool has_hot_loop>
    CK_TILE_DEVICE void operator()(SharedWGDramWindow& shared_wg_dram_window,
                                   PrivateWGDramWindowMajor& private_wg_dram_window_major,
                                   PrivateWGDramWindowMinor& private_wg_dram_window_minor,
                                   SharedWGLdsWindows& shared_wg_lds_windows,
                                   PrivateWGLdsWindowsMajor& private_wg_lds_windows_major,
                                   PrivateWGLdsWindowsMinor& private_wg_lds_windows_minor,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>) const
    {
        // issue initial mls loads
        static_for<0, NumLdsStages, 1>{}([&](auto i) {
            async_mls_load_tile_asm(private_wg_lds_windows_major(i), private_wg_dram_window_major);
            async_mls_load_tile_asm(shared_wg_lds_windows(i), shared_wg_dram_window);
            async_mls_load_tile_asm(private_wg_lds_windows_minor(i), private_wg_dram_window_minor);

            if constexpr(i != NumLdsStages - 1)
            {
                advance_tile_window(private_wg_dram_window_major);
                advance_tile_window(shared_wg_dram_window);
                advance_tile_window(private_wg_dram_window_minor);
            }
        });

        constexpr uint32_t mls_issue_cnt_pr_major = PrivateWGDramWindowMajor::get_num_of_access();
        constexpr uint32_t mls_issue_cnt_sh       = SharedWGDramWindow::get_num_of_access();
        constexpr uint32_t mls_issue_cnt_pr_minor = PrivateWGDramWindowMinor::get_num_of_access();
        constexpr uint32_t mls_issue_cnt_per_stage =
            mls_issue_cnt_pr_major + mls_issue_cnt_sh + mls_issue_cnt_pr_minor;

        // wait first stage
        __builtin_amdgcn_sched_barrier(0);
        async_load_fence(mls_issue_cnt_per_stage * (NumLdsStages - 1));
        __builtin_amdgcn_sched_barrier(0);

        // notify consumer
        __builtin_amdgcn_sched_barrier(0);
        wg_sync(bool_constant<true>{});
        __builtin_amdgcn_sched_barrier(0);

        // producer loop func
        const auto producer_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr bool is_last_loop = is_tail_loop && (i == NumLdsStages - 1);

            constexpr uint32_t waitcnt =
                is_tail_loop
                    ? mls_issue_cnt_per_stage * (NumLdsStages - i - 2)
                    : mls_issue_cnt_per_stage * (NumLdsStages - 2) + mls_issue_cnt_pr_major;

            // wait stage i-th lds buffer to be released
            wg_sync(bool_constant<true>{});

            if constexpr(!is_tail_loop)
            {
                // issue prefetch pr_major to i-th lds buffer
                advance_tile_window(private_wg_dram_window_major);
                async_mls_load_tile_asm(private_wg_lds_windows_major(i),
                                        private_wg_dram_window_major);
            }

            if constexpr(!is_last_loop)
            {
                // wait stage i+1
                __builtin_amdgcn_sched_barrier(0);
                async_load_fence(waitcnt);
                __builtin_amdgcn_sched_barrier(0);
            }

            // notify major consumer
            __builtin_amdgcn_sched_barrier(0);
            wg_sync(bool_constant<true>{});
            __builtin_amdgcn_sched_barrier(0);

            if constexpr(!is_tail_loop)
            {
                // issue prefetch sh/pr_minor to i-th lds buffer
                advance_tile_window(shared_wg_dram_window);
                advance_tile_window(private_wg_dram_window_minor);
                async_mls_load_tile_asm(shared_wg_lds_windows(i), shared_wg_dram_window);
                async_mls_load_tile_asm(private_wg_lds_windows_minor(i),
                                        private_wg_dram_window_minor);
            }
        };

        // main loop
        if constexpr(has_hot_loop)
        {
            index_t loop = 0;

            do
            {
                static_for<0, NumLdsStages, 1>{}(
                    [&](auto i) { producer_loop_fn(i, bool_constant<false>{}); });

                loop += NumLdsStages;

            } while(loop < (num_loop - NumLdsStages));
        }

        // tail loop
        {
            static_for<0, NumLdsStages, 1>{}(
                [&](auto i) { producer_loop_fn(i, bool_constant<true>{}); });
        }
    }

    template <typename SharedWGLdsWindows,
              typename PrivateWGLdsWindows,
              typename BlockGemm,
              bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(SharedWGLdsWindows& shared_wg_lds_windows,
                                   PrivateWGLdsWindows& private_wg_lds_windows,
                                   const BlockGemm& block_gemm,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>,
                                   number<0>) const
    {
        auto acc_block_tensor = block_gemm.MakeAccBlockTile();

        // initialize acc tensor
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, acc_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // wait sh/pr load
        __builtin_amdgcn_sched_barrier(0);
        wg_sync(bool_constant<true>{});
        __builtin_amdgcn_sched_barrier(0);

        // issue ds read
        promote_prio();
        auto in_warp_tensors =
            is_input_shared ? block_gemm.GetAWarpTensors(shared_wg_lds_windows(number<0>{}))
                            : block_gemm.GetAWarpTensors(private_wg_lds_windows(number<0>{}));
        auto wei_warp_tensors =
            is_input_shared ? block_gemm.GetBWarpTensors(private_wg_lds_windows(number<0>{}))
                            : block_gemm.GetBWarpTensors(shared_wg_lds_windows(number<0>{}));
        restore_prio();

        const auto compute_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto i_next = number<(i + 1) % NumLdsStages>{};

            constexpr bool is_last_loop = is_tail_loop && (i == NumLdsStages - 1);

            // lds wait
            lds_fence();

            // notify producer, i-th stage lds buffer of pr_major is released
            wg_sync(bool_constant<true>{});

            // issue mmac
            promote_prio();
            block_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
            restore_prio();

            // wait i+1-th stage lds buffer ready
            wg_sync(bool_constant<true>{});

            if constexpr(!is_last_loop)
            {
                // issue ds prefetch
                promote_prio();
                in_warp_tensors  = is_input_shared
                                       ? block_gemm.GetAWarpTensors(shared_wg_lds_windows(i_next))
                                       : block_gemm.GetAWarpTensors(private_wg_lds_windows(i_next));
                wei_warp_tensors = is_input_shared
                                       ? block_gemm.GetBWarpTensors(private_wg_lds_windows(i_next))
                                       : block_gemm.GetBWarpTensors(shared_wg_lds_windows(i_next));
                restore_prio();
            }
        };

        // main loop
        if constexpr(has_hot_loop)
        {
            index_t loop = 0;

            do
            {
                static_for<0, NumLdsStages, 1>{}(
                    [&](auto i) { compute_loop_fn(i, bool_constant<false>{}); });

                loop += NumLdsStages;

            } while(loop < (num_loop - NumLdsStages));
        }

        // tail
        {
            static_for<0, NumLdsStages, 1>{}(
                [&](auto i) { compute_loop_fn(i, bool_constant<true>{}); });
        }

        return block_gemm.MakePermutedAccBlockTile(acc_block_tensor);
    }

    template <typename SharedWGLdsWindows,
              typename PrivateWGLdsWindows,
              typename BlockGemm,
              bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(SharedWGLdsWindows& shared_wg_lds_windows,
                                   PrivateWGLdsWindows& private_wg_lds_windows,
                                   const BlockGemm& block_gemm,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>,
                                   number<1>) const
    {
        auto acc_block_tensor = block_gemm.MakeAccBlockTile();

        // initialize acc tensor
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, acc_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        wg_sync(bool_constant<true>{});

        const auto compute_loop_fn = [&](auto i) {
            // wait sh/pr_minor load
            wg_sync(bool_constant<true>{});

            // issue ds read
            promote_prio();
            auto in_warp_tensors  = is_input_shared
                                        ? block_gemm.GetAWarpTensors(shared_wg_lds_windows(i))
                                        : block_gemm.GetAWarpTensors(private_wg_lds_windows(i));
            auto wei_warp_tensors = is_input_shared
                                        ? block_gemm.GetBWarpTensors(private_wg_lds_windows(i))
                                        : block_gemm.GetBWarpTensors(shared_wg_lds_windows(i));
            restore_prio();

            // wait lds
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            __builtin_amdgcn_sched_barrier(0);

            // notify producer i-th stage of lds buffer sh/pr_minor released
            wg_sync(bool_constant<true>{});

            // issue mmac
            promote_prio();
            block_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
            restore_prio();
        };

        // main loop
        if constexpr(has_hot_loop)
        {
            index_t loop = 0;

            do
            {
                static_for<0, NumLdsStages, 1>{}([&](auto i) { compute_loop_fn(i); });

                loop += NumLdsStages;

            } while(loop < (num_loop - NumLdsStages));
        }

        // tail
        {
            static_for<0, NumLdsStages, 1>{}([&](auto i) { compute_loop_fn(i); });
        }

        return block_gemm.MakePermutedAccBlockTile(acc_block_tensor);
    }
};

} // namespace ck_tile
