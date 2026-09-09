// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_, bool oob_check_ = false>
struct FusedConvIgemmPipelineWaspAgmemBgmemCregV3
{
    using Problem = remove_cvref_t<Problem_>;
    using Policy  = remove_cvref_t<Policy_>;

    static constexpr index_t NumLdsStages = Problem::NumLdsStages;
    static constexpr index_t FilterUnroll = Problem::FilterUnroll;
    static constexpr index_t LoopUnroll =
        FilterUnroll % NumLdsStages == 0 ? FilterUnroll : FilterUnroll * NumLdsStages;

    // compute warp groups
    static constexpr index_t MWGs = Problem::MWGs;
    static constexpr index_t NWGs = Problem::NWGs;

    static constexpr bool is_input_shared = Problem::is_input_shared;

    // enable oob_check_ will generate addtional instructions for oob handling
    // performance may degree on devices without valu-mmop co-issue
    // thus it's disabled by default, but need to gurantee there's no oob access
    static constexpr auto oob_check = bool_constant<oob_check_>{};

    CK_TILE_HOST static bool IsSupported(const index_t num_loop)
    {
        return (num_loop % LoopUnroll) == 0;
    }

    CK_TILE_HOST static bool CalculateHasMainLoop(const index_t num_loop)
    {
        return (num_loop / LoopUnroll) > 1;
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
        // issue initial buffer loads
        static_for<0, NumLdsStages, 1>{}([&](auto i) {
            constexpr auto samp_idx = number<i % FilterUnroll>{};

            async_load_tile_wrapped_asm(private_wg_lds_windows_major(i),
                                        private_wg_dram_window_major,
                                        samp_idx,
                                        number<-1>{},
                                        oob_check);
            async_load_tile_wrapped_asm(
                shared_wg_lds_windows(i), shared_wg_dram_window, samp_idx, number<-1>{}, oob_check);
            async_load_tile_wrapped_asm(private_wg_lds_windows_minor(i),
                                        private_wg_dram_window_minor,
                                        samp_idx,
                                        number<-1>{},
                                        oob_check);

            if constexpr(i != NumLdsStages - 1)
            {
                advance_tile_window(private_wg_dram_window_major, number<samp_idx + 1>{});
                advance_tile_window(shared_wg_dram_window, number<samp_idx + 1>{});
                advance_tile_window(private_wg_dram_window_minor, number<samp_idx + 1>{});
            }
        });

        constexpr uint32_t issue_cnt_pr_major = PrivateWGDramWindowMajor::get_num_of_access();
        constexpr uint32_t issue_cnt_sh       = SharedWGDramWindow::get_num_of_access();
        constexpr uint32_t issue_cnt_pr_minor = PrivateWGDramWindowMinor::get_num_of_access();
        constexpr uint32_t issue_cnt_per_stage =
            issue_cnt_pr_major + issue_cnt_sh + issue_cnt_pr_minor;

        // wait first stage
        __builtin_amdgcn_sched_barrier(0);
        async_load_fence(issue_cnt_per_stage * (NumLdsStages - 1));
        __builtin_amdgcn_sched_barrier(0);

        // notify consumer
        __builtin_amdgcn_sched_barrier(0);
        wg_sync(bool_constant<true>{});
        __builtin_amdgcn_sched_barrier(0);

        // producer loop func
        const auto producer_loop_fn = [&](auto unroll_i, auto is_unroll_tail_loop) {
            constexpr auto i        = number<unroll_i % NumLdsStages>{};
            constexpr auto samp_idx = number<(unroll_i + NumLdsStages) % FilterUnroll>{};

            constexpr bool is_tail_loop =
                is_unroll_tail_loop && (unroll_i >= (LoopUnroll - NumLdsStages));
            constexpr bool is_last_loop = is_tail_loop && (i == NumLdsStages - 1);

            constexpr uint32_t waitcnt =
                NumLdsStages == 1 ? 0
                : is_tail_loop    ? issue_cnt_per_stage * (NumLdsStages - i - 2)
                                  : issue_cnt_per_stage * (NumLdsStages - 2) + issue_cnt_pr_major;

            // wait stage i-th lds buffer to be released
            wg_sync(bool_constant<true>{});

            if constexpr(!is_tail_loop)
            {
                // issue prefetch pr_major to i-th lds buffer
                advance_tile_window(private_wg_dram_window_major, samp_idx);
                advance_tile_window(shared_wg_dram_window, samp_idx);
                advance_tile_window(private_wg_dram_window_minor, samp_idx);

                if constexpr(NumLdsStages == 1)
                {
                    async_load_tile_wrapped_asm(private_wg_lds_windows_major(i),
                                                private_wg_dram_window_major,
                                                samp_idx,
                                                number<-1>{},
                                                oob_check);
                    async_load_tile_wrapped_asm(shared_wg_lds_windows(i),
                                                shared_wg_dram_window,
                                                samp_idx,
                                                number<-1>{},
                                                oob_check);
                    async_load_tile_wrapped_asm(private_wg_lds_windows_minor(i),
                                                private_wg_dram_window_minor,
                                                samp_idx,
                                                number<-1>{},
                                                oob_check);
                }
                else
                {
                    async_load_tile_wrapped_asm(private_wg_lds_windows_major(i),
                                                private_wg_dram_window_major,
                                                samp_idx,
                                                number<-1>{},
                                                oob_check);
                }
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

            if constexpr(NumLdsStages > 1)
            {
                if constexpr(!is_tail_loop)
                {
                    // issue prefetch pr_minor/sh to i-th lds buffer
                    async_load_tile_wrapped_asm(shared_wg_lds_windows(i),
                                                shared_wg_dram_window,
                                                samp_idx,
                                                number<-1>{},
                                                oob_check);
                    async_load_tile_wrapped_asm(private_wg_lds_windows_minor(i),
                                                private_wg_dram_window_minor,
                                                samp_idx,
                                                number<-1>{},
                                                oob_check);
                }
            }
        };

        // main loop
        if constexpr(has_hot_loop)
        {
            index_t loop = 0;

            do
            {
                static_for<0, LoopUnroll, 1>{}(
                    [&](auto i) { producer_loop_fn(i, bool_constant<false>{}); });

                loop += LoopUnroll;

            } while(loop < (num_loop - LoopUnroll));
        }

        // tail loop
        {
            static_for<0, LoopUnroll, 1>{}(
                [&](auto i) { producer_loop_fn(i, bool_constant<true>{}); });
        }
    }

    template <typename SharedWarpWindows,
              typename PrivateWarpWindows,
              typename BlockGemm,
              bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(const SharedWarpWindows& shared_warp_windows,
                                   const PrivateWarpWindows& private_warp_windows,
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

        if constexpr(is_input_shared)
        {
            // issue ds read
            promote_prio();
            auto in_warp_tensors  = block_gemm.GetAWarpTensors(shared_warp_windows[number<0>{}]);
            auto wei_warp_tensors = block_gemm.GetBWarpTensors(private_warp_windows[number<0>{}]);
            restore_prio();

            const auto compute_loop_fn = [&](auto unroll_i, auto is_unroll_tail_loop) {
                constexpr auto i      = number<unroll_i % NumLdsStages>{};
                constexpr auto i_next = number<(i + 1) % NumLdsStages>{};

                constexpr bool is_tail_loop =
                    is_unroll_tail_loop && (unroll_i >= (LoopUnroll - NumLdsStages));
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
                    in_warp_tensors  = block_gemm.GetAWarpTensors(shared_warp_windows[i_next]);
                    wei_warp_tensors = block_gemm.GetBWarpTensors(private_warp_windows[i_next]);
                    restore_prio();
                }
            };

            // main loop
            if constexpr(has_hot_loop)
            {
                index_t loop = 0;

                do
                {
                    static_for<0, LoopUnroll, 1>{}(
                        [&](auto i) { compute_loop_fn(i, bool_constant<false>{}); });

                    loop += LoopUnroll;

                } while(loop < (num_loop - LoopUnroll));
            }

            // tail
            {
                static_for<0, LoopUnroll, 1>{}(
                    [&](auto i) { compute_loop_fn(i, bool_constant<true>{}); });
            }
        }
        else
        {
            // issue ds read
            promote_prio();
            auto in_warp_tensors  = block_gemm.GetAWarpTensors(private_warp_windows[number<0>{}]);
            auto wei_warp_tensors = block_gemm.GetBWarpTensors(shared_warp_windows[number<0>{}]);
            restore_prio();

            const auto compute_loop_fn = [&](auto unroll_i, auto is_unroll_tail_loop) {
                constexpr auto i      = number<unroll_i % NumLdsStages>{};
                constexpr auto i_next = number<(i + 1) % NumLdsStages>{};

                constexpr bool is_tail_loop =
                    is_unroll_tail_loop && (unroll_i >= (LoopUnroll - NumLdsStages));
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
                    in_warp_tensors  = block_gemm.GetAWarpTensors(private_warp_windows[i_next]);
                    wei_warp_tensors = block_gemm.GetBWarpTensors(shared_warp_windows[i_next]);
                    restore_prio();
                }
            };

            // main loop
            if constexpr(has_hot_loop)
            {
                index_t loop = 0;

                do
                {
                    static_for<0, LoopUnroll, 1>{}(
                        [&](auto i) { compute_loop_fn(i, bool_constant<false>{}); });

                    loop += LoopUnroll;

                } while(loop < (num_loop - LoopUnroll));
            }

            // tail
            {
                static_for<0, LoopUnroll, 1>{}(
                    [&](auto i) { compute_loop_fn(i, bool_constant<true>{}); });
            }
        }

        return acc_block_tensor;
    }

    template <typename SharedWarpWindows,
              typename PrivateWarpWindows,
              typename BlockGemm,
              bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(const SharedWarpWindows& shared_warp_windows,
                                   const PrivateWarpWindows& private_warp_windows,
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

        if constexpr(is_input_shared)
        {
            const auto compute_loop_fn = [&](auto unroll_i) {
                constexpr auto i = number<unroll_i % NumLdsStages>{};

                if constexpr(NumLdsStages > 1)
                {

                    // wait sh/pr_minor load
                    wg_sync(bool_constant<true>{});

                    // issue ds read
                    promote_prio();
                    auto in_warp_tensors  = block_gemm.GetAWarpTensors(shared_warp_windows[i]);
                    auto wei_warp_tensors = block_gemm.GetBWarpTensors(private_warp_windows[i]);
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
                }
                else
                {
                    // issue ds read
                    promote_prio();
                    auto in_warp_tensors  = block_gemm.GetAWarpTensors(shared_warp_windows[i]);
                    auto wei_warp_tensors = block_gemm.GetBWarpTensors(private_warp_windows[i]);
                    restore_prio();

                    // wait lds
                    __builtin_amdgcn_sched_barrier(0);
                    lds_fence();
                    __builtin_amdgcn_sched_barrier(0);

                    // wait sh/pr_minor load
                    wg_sync(bool_constant<true>{});

                    // notify producer i-th stage of lds buffer sh/pr_minor released
                    wg_sync(bool_constant<true>{});

                    // issue mmac
                    promote_prio();
                    block_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();
                }
            };

            // main loop
            if constexpr(has_hot_loop)
            {
                index_t loop = 0;

                do
                {
                    static_for<0, LoopUnroll, 1>{}([&](auto i) { compute_loop_fn(i); });

                    loop += LoopUnroll;

                } while(loop < (num_loop - LoopUnroll));
            }

            // tail
            {
                static_for<0, LoopUnroll, 1>{}([&](auto i) { compute_loop_fn(i); });
            }
        }
        else
        {
            const auto compute_loop_fn = [&](auto unroll_i) {
                constexpr auto i = number<unroll_i % NumLdsStages>{};

                if constexpr(NumLdsStages > 1)
                {
                    // wait sh/pr_minor load
                    wg_sync(bool_constant<true>{});

                    // issue ds read
                    promote_prio();
                    auto in_warp_tensors  = block_gemm.GetAWarpTensors(private_warp_windows[i]);
                    auto wei_warp_tensors = block_gemm.GetBWarpTensors(shared_warp_windows[i]);
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
                }
                else
                {
                    // issue ds read
                    promote_prio();
                    auto in_warp_tensors  = block_gemm.GetAWarpTensors(private_warp_windows[i]);
                    auto wei_warp_tensors = block_gemm.GetBWarpTensors(shared_warp_windows[i]);
                    restore_prio();

                    // wait lds
                    __builtin_amdgcn_sched_barrier(0);
                    lds_fence();
                    __builtin_amdgcn_sched_barrier(0);
                    // wait sh/pr_minor load
                    wg_sync(bool_constant<true>{});

                    // notify producer i-th stage of lds buffer sh/pr_minor released
                    wg_sync(bool_constant<true>{});

                    // issue mmac
                    promote_prio();
                    block_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();
                }
            };

            // main loop
            if constexpr(has_hot_loop)
            {
                index_t loop = 0;

                do
                {
                    static_for<0, LoopUnroll, 1>{}([&](auto i) { compute_loop_fn(i); });

                    loop += LoopUnroll;

                } while(loop < (num_loop - LoopUnroll));
            }

            // tail
            {
                static_for<0, LoopUnroll, 1>{}([&](auto i) { compute_loop_fn(i); });
            }
        }

        return acc_block_tensor;
    }
};

} // namespace ck_tile
