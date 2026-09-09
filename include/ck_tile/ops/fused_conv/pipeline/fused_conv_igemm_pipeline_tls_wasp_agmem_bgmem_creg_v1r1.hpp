// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_>
struct FusedConvIgemmPipelineTlsWaspAgmemBgmemCregV1R1
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

    static constexpr auto ebar_load_wv_cnt    = 2 * Problem::SubWGSize;
    static constexpr auto ebar_free_sh_wv_cnt = 3 * Problem::SubWGSize;
    static constexpr auto ebar_free_pr_wv_cnt = 2 * Problem::SubWGSize;

    CK_TILE_HOST static bool IsSupported(const index_t num_loop)
    {
        return (num_loop % LoopUnroll) == 0;
    }

    CK_TILE_HOST static bool CalculateHasMainLoop(const index_t num_loop)
    {
        return (num_loop / LoopUnroll) > 0;
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

    CK_TILE_DEVICE FusedConvIgemmPipelineTlsWaspAgmemBgmemCregV1R1()
    {
        static_assert(NumLdsStages * 5 <= 16, "At most 16 ebarriers supported!");

        // init ebarriers
        static_for<0, NumLdsStages, 1>{}([&](auto i) {
            ebar_load_sh_pr_major(i) = hcu_ebarrier{i, ebar_load_wv_cnt};
            ebar_load_pr_minor(i)    = hcu_ebarrier{NumLdsStages + i, ebar_load_wv_cnt};
            ebar_free_sh(i)          = hcu_ebarrier{2 * NumLdsStages + i, ebar_free_sh_wv_cnt};
            ebar_free_pr_major(i)    = hcu_ebarrier{3 * NumLdsStages + i, ebar_free_pr_wv_cnt};
            ebar_free_pr_minor(i)    = hcu_ebarrier{4 * NumLdsStages + i, ebar_free_pr_wv_cnt};
        });
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
        // issue initial tls load
        static_for<0, NumLdsStages - 1, 1>{}([&](auto i) {
            constexpr auto samp_idx = number<i % FilterUnroll>{};

            async_tls_load_tile_asm(shared_wg_lds_windows(i), shared_wg_dram_window, samp_idx);
            async_tls_load_tile_asm(
                private_wg_lds_windows_major(i), private_wg_dram_window_major, samp_idx);
            async_tls_load_tile_asm(
                private_wg_lds_windows_minor(i), private_wg_dram_window_minor, samp_idx);

            test_and_advance_tile_window(shared_wg_dram_window, number<samp_idx + 1>{});
            test_and_advance_tile_window(private_wg_dram_window_major, number<samp_idx + 1>{});
            test_and_advance_tile_window(private_wg_dram_window_minor, number<samp_idx + 1>{});
        });

        {
            constexpr auto samp_idx = number<(NumLdsStages - 1) % FilterUnroll>{};

            async_tls_load_tile_asm(
                shared_wg_lds_windows(number<NumLdsStages - 1>{}), shared_wg_dram_window, samp_idx);
            async_tls_load_tile_asm(private_wg_lds_windows_major(number<NumLdsStages - 1>{}),
                                    private_wg_dram_window_major,
                                    samp_idx);
            async_tls_load_tile_asm(private_wg_lds_windows_minor(number<NumLdsStages - 1>{}),
                                    private_wg_dram_window_minor,
                                    samp_idx);
        }

        // wait first
        constexpr uint32_t tls_issue_cnt_sh       = SharedWGDramWindow::get_num_of_access();
        constexpr uint32_t tls_issue_cnt_pr_major = PrivateWGDramWindowMajor::get_num_of_access();
        constexpr uint32_t tls_issue_cnt_pr_minor = PrivateWGDramWindowMinor::get_num_of_access();
        constexpr uint32_t tls_issue_cnt =
            tls_issue_cnt_sh + tls_issue_cnt_pr_major + tls_issue_cnt_pr_minor;

        // wait sh and pr_major tls load
        __builtin_amdgcn_sched_barrier(0);
        async_load_fence(tls_issue_cnt * NumLdsStages - tls_issue_cnt_sh - tls_issue_cnt_pr_major);
        __builtin_amdgcn_sched_barrier(0);

        // notify shared tls load for major compute WGs
        __builtin_amdgcn_sched_barrier(0);
        ebar_load_sh_pr_major[number<0>{}].arrive();
        __builtin_amdgcn_sched_barrier(0);

        // producer loop func
        const auto producer_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto lds_stage = number<i % NumLdsStages>{};
            constexpr auto samp_idx  = number<(i + NumLdsStages) % FilterUnroll>{};

            constexpr bool is_last_loop = is_tail_loop && (i == LoopUnroll - 1);

            // vmcnt calculation
            constexpr uint32_t waitcnt_pr_minor =
                is_tail_loop ? tls_issue_cnt * (NumLdsStages - lds_stage - 1)
                             : tls_issue_cnt * (NumLdsStages - 1);

            constexpr uint32_t waitcnt_shpr_major =
                is_tail_loop
                    ? tls_issue_cnt * (NumLdsStages - lds_stage - 1) - tls_issue_cnt_sh -
                          tls_issue_cnt_pr_major
                    : tls_issue_cnt * NumLdsStages - tls_issue_cnt_sh - tls_issue_cnt_pr_major;

            // wait pr_minor tls load and notify for minor compute WGs
            __builtin_amdgcn_sched_barrier(0);
            async_load_fence(waitcnt_pr_minor);
            ebar_load_pr_minor[lds_stage].arrive();
            __builtin_amdgcn_sched_barrier(0);

            // TG sync before loop
            __builtin_amdgcn_sched_barrier(0);
            wg_sync(bool_constant<true>{});
            __builtin_amdgcn_sched_barrier(0);

            // skip tls issue in tail loop
            if constexpr(!is_tail_loop)
            {
                // advance to current samp_idx
                test_and_advance_tile_window(shared_wg_dram_window, number<samp_idx>{});
                test_and_advance_tile_window(private_wg_dram_window_major, number<samp_idx>{});
                test_and_advance_tile_window(private_wg_dram_window_minor, number<samp_idx>{});

                // issue sh/pr_major after free sync
                __builtin_amdgcn_sched_barrier(0);
                ebar_free_sh[lds_stage].sync();
                ebar_free_pr_major[lds_stage].sync();
                async_tls_load_tile_asm(
                    shared_wg_lds_windows(lds_stage), shared_wg_dram_window, samp_idx);
                async_tls_load_tile_asm(private_wg_lds_windows_major(lds_stage),
                                        private_wg_dram_window_major,
                                        samp_idx);

                // issue pr_minor after free sync
                __builtin_amdgcn_sched_barrier(0);
                ebar_free_pr_minor[lds_stage].sync();
                async_tls_load_tile_asm(private_wg_lds_windows_minor(lds_stage),
                                        private_wg_dram_window_minor,
                                        samp_idx);
                __builtin_amdgcn_sched_barrier(0);
            }

            // skip sh and pr_major wait in last loop
            if constexpr(!is_last_loop)
            {
                // wait sh and pr_major tls load
                __builtin_amdgcn_sched_barrier(0);
                async_load_fence(waitcnt_shpr_major);
                __builtin_amdgcn_sched_barrier(0);

                // notify shared tls load for major compute WGs
                __builtin_amdgcn_sched_barrier(0);
                ebar_load_sh_pr_major[lds_stage].arrive();
                __builtin_amdgcn_sched_barrier(0);
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
            static_for<0, LoopUnroll, 1>{}([&](auto i) {
                if constexpr(i < LoopUnroll - NumLdsStages)
                {
                    producer_loop_fn(i, bool_constant<false>{});
                }
                else
                {
                    producer_loop_fn(i, bool_constant<true>{});
                }
            });
        }
    }

    template <typename SharedWGLdsWindows, typename PrivateWGLdsWindows, bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(SharedWGLdsWindows& shared_wg_lds_windows,
                                   PrivateWGLdsWindows& private_wg_lds_windows,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>,
                                   number<0>) const
    {
        const auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto acc_block_tensor = blockwise_gemm.MakeAccBlockTile();

        // initialize acc tensor
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, acc_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // wait sh/pr load
        __builtin_amdgcn_sched_barrier(0);
        ebar_load_sh_pr_major[number<0>{}].sync();
        __builtin_amdgcn_sched_barrier(0);

        // TG sync before loop
        __builtin_amdgcn_sched_barrier(0);
        wg_sync(bool_constant<true>{});
        __builtin_amdgcn_sched_barrier(0);

        // issue ds read
        promote_prio();
        // TODO: ensure this can be done at compile time
        auto in_warp_tensors =
            is_input_shared ? blockwise_gemm.GetAWarpTensors(shared_wg_lds_windows(number<0>{}))
                            : blockwise_gemm.GetAWarpTensors(private_wg_lds_windows(number<0>{}));
        auto wei_warp_tensors =
            is_input_shared ? blockwise_gemm.GetBWarpTensors(private_wg_lds_windows(number<0>{}))
                            : blockwise_gemm.GetBWarpTensors(shared_wg_lds_windows(number<0>{}));
        restore_prio();

        const auto compute_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto lds_stage      = number<i % NumLdsStages>{};
            constexpr auto lds_stage_next = number<(lds_stage + 1) % NumLdsStages>{};

            constexpr bool is_last_loop = is_tail_loop && (i == LoopUnroll - 1);

            // lds wait
            lds_fence();

            if constexpr(!is_tail_loop)
            {
                // notify producer that lds read is done
                ebar_free_sh[lds_stage].arrive();
                ebar_free_pr_major[lds_stage].arrive();
            }

            // issue mmac
            promote_prio();
            blockwise_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
            restore_prio();

            if constexpr(!is_last_loop)
            {
                // wait sh/pr_major load
                ebar_load_sh_pr_major[lds_stage].sync();

                // issue ds prefetch
                // TODO: ensure this can be done at compile time
                promote_prio();
                in_warp_tensors =
                    is_input_shared
                        ? blockwise_gemm.GetAWarpTensors(shared_wg_lds_windows(lds_stage_next))
                        : blockwise_gemm.GetAWarpTensors(private_wg_lds_windows(lds_stage_next));
                wei_warp_tensors =
                    is_input_shared
                        ? blockwise_gemm.GetBWarpTensors(private_wg_lds_windows(lds_stage_next))
                        : blockwise_gemm.GetBWarpTensors(shared_wg_lds_windows(lds_stage_next));
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
            static_for<0, LoopUnroll, 1>{}([&](auto i) {
                if constexpr(i < LoopUnroll - NumLdsStages)
                {
                    compute_loop_fn(i, bool_constant<false>{});
                }
                else
                {
                    compute_loop_fn(i, bool_constant<true>{});
                }
            });
        }

        return blockwise_gemm.MakePermutedAccBlockTile(acc_block_tensor);
    }

    template <typename SharedWGLdsWindows, typename PrivateWGLdsWindows, bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(SharedWGLdsWindows& shared_wg_lds_windows,
                                   PrivateWGLdsWindows& private_wg_lds_windows,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>,
                                   number<1>) const
    {
        const auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto acc_block_tensor = blockwise_gemm.MakeAccBlockTile();

        // initialize acc tensor
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, acc_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // TG sync before loop
        __builtin_amdgcn_sched_barrier(0);
        wg_sync(bool_constant<true>{});
        __builtin_amdgcn_sched_barrier(0);

        const auto compute_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto lds_stage = number<i % NumLdsStages>{};

            // wait sh/pr_minor load
            ebar_load_pr_minor[lds_stage].sync();

            // issue ds read
            promote_prio();
            // TODO: ensure this can be done at compile time
            auto in_warp_tensors =
                is_input_shared ? blockwise_gemm.GetAWarpTensors(shared_wg_lds_windows(lds_stage))
                                : blockwise_gemm.GetAWarpTensors(private_wg_lds_windows(lds_stage));
            auto wei_warp_tensors =
                is_input_shared ? blockwise_gemm.GetBWarpTensors(private_wg_lds_windows(lds_stage))
                                : blockwise_gemm.GetBWarpTensors(shared_wg_lds_windows(lds_stage));
            restore_prio();

            // wait lds
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            __builtin_amdgcn_sched_barrier(0);

            if constexpr(!is_tail_loop)
            {
                // notify producer that lds read is done
                ebar_free_sh[lds_stage].arrive();
                ebar_free_pr_minor[lds_stage].arrive();
            }

            // issue mmac
            promote_prio();
            blockwise_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
            restore_prio();
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
            static_for<0, LoopUnroll, 1>{}([&](auto i) {
                if constexpr(i < LoopUnroll - NumLdsStages)
                {
                    compute_loop_fn(i, bool_constant<false>{});
                }
                else
                {
                    compute_loop_fn(i, bool_constant<true>{});
                }
            });
        }

        return blockwise_gemm.MakePermutedAccBlockTile(acc_block_tensor);
    }

    // ebarriers for load/free
    array<hcu_ebarrier, NumLdsStages> ebar_load_sh_pr_major;
    array<hcu_ebarrier, NumLdsStages> ebar_load_pr_minor;
    array<hcu_ebarrier, NumLdsStages> ebar_free_sh;
    array<hcu_ebarrier, NumLdsStages> ebar_free_pr_major;
    array<hcu_ebarrier, NumLdsStages> ebar_free_pr_minor;
};

} // namespace ck_tile
