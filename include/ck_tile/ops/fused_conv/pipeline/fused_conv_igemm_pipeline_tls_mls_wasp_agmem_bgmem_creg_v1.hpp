// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv.hpp"
#include "ck_tile/ops/fused_conv/pipeline/fused_conv_igemm_pipeline_tls_wasp_base.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_, typename WGs>
struct FusedConvIgemmPipelineTlsMlsWaspAgmemBgmemCregV1;

template <typename Problem_, typename Policy_>
struct FusedConvIgemmPipelineTlsMlsWaspAgmemBgmemCregV1<Problem_, Policy_, sequence<1, 2>>
{
    using Base = FusedConvIgemmPipelineTlsWaspBase<Problem_, Policy_>;

    using Problem = typename Base::Problem;
    using Policy  = typename Base::Policy;

    static constexpr index_t NumLdsStages = Base::NumLdsStages;
    static constexpr index_t FilterUnroll = Base::FilterUnroll;
    static constexpr index_t LoopUnroll   = Base::LoopUnroll;

    static constexpr auto bar_load_wv_cnt     = 2 * Problem::SubWGSize;
    static constexpr auto bar_free_in_wv_cnt  = 3 * Problem::SubWGSize;
    static constexpr auto bar_free_wei_wv_cnt = 2 * Problem::SubWGSize;

    CK_TILE_HOST static bool IsSupported(const index_t num_loop)
    {
        return Base::IsSupported(num_loop);
    }

    CK_TILE_HOST static bool CalculateHasMainLoop(const index_t num_loop)
    {
        return Base::CalculateHasMainLoop(num_loop);
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize() { return Base::GetLdsByteSize(); }

    CK_TILE_DEVICE static bool IsProducerWG() { return Base::IsProducerWG(); }

    CK_TILE_DEVICE static bool IsComputeWG0() { return Base::IsMajorComputeWG(); }

    CK_TILE_DEVICE static bool IsComputeWG1() { return Base::IsMinorComputeWG(); }

    CK_TILE_DEVICE FusedConvIgemmPipelineTlsMlsWaspAgmemBgmemCregV1()
        : ebar_load_in_wg0(0, bar_load_wv_cnt),
          ebar_load_in_wg1(0, bar_load_wv_cnt),
          ebar_free_in(0, bar_free_in_wv_cnt),
          ebar_free_wei_wg0(0, bar_free_wei_wv_cnt),
          ebar_free_wei_wg1(0, bar_free_wei_wv_cnt)
    {
        // init_and_sync abars
        static_for<0, NumLdsStages, 1>{}([&](auto i) {
            abars_wei_wg0[i] = hcu_abarrier{i, bar_load_wv_cnt};
            abars_wei_wg1[i] = hcu_abarrier{i + NumLdsStages, bar_load_wv_cnt};
        });
    }

    // producer pipeline
    template <typename InWGDramWindow,
              typename WeiWG0DramWindow,
              typename WeiWG1DramWindow,
              typename InWGLdsWindows,
              typename WeiWG0LdsWindows,
              typename WeiWG1LdsWindows,
              bool has_hot_loop>
    CK_TILE_DEVICE void operator()(InWGDramWindow& in_wg_dram_window,
                                   WeiWG0DramWindow& wei_wg0_dram_window,
                                   WeiWG1DramWindow& wei_wg1_dram_window,
                                   InWGLdsWindows& in_wg_lds_windows,
                                   WeiWG0LdsWindows& wei_wg0_lds_windows,
                                   WeiWG1LdsWindows& wei_wg1_lds_windows,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>) const
    {
        // issue initial tls load
        static_for<0, NumLdsStages, 1>{}([&](auto i) {
            constexpr auto samp_idx = number<i % FilterUnroll>{};

            // tls issue
            async_tls_load_tile_asm(in_wg_lds_windows(i), in_wg_dram_window, samp_idx);

            // init_and_sync abar
            abars_wei_wg0[i].init_and_sync(0);
            abars_wei_wg1[i].init_and_sync(0);

            // track bps mls load for wg0
            abars_wei_wg0[i].track();
            async_mls_bps_load_tile_asm(wei_wg0_lds_windows(i), wei_wg0_dram_window);
            abars_wei_wg0[i].arrive();

            // track bps mls load for wg1
            abars_wei_wg1[i].track();
            async_mls_bps_load_tile_asm(wei_wg1_lds_windows(i), wei_wg1_dram_window);
            abars_wei_wg1[i].arrive();

            if constexpr(i != NumLdsStages - 1)
            {
                // advance tls/mls window
                __builtin_amdgcn_sched_barrier(0);
                test_and_advance_tile_window(in_wg_dram_window, number<samp_idx + 1>{});
                advance_tile_window(wei_wg0_dram_window);
                advance_tile_window(wei_wg1_dram_window);
                __builtin_amdgcn_sched_barrier(0);
            }
        });

        constexpr uint32_t tls_issue_cnt = InWGDramWindow::get_num_of_access();

        // wait first in tls load
        __builtin_amdgcn_sched_barrier(0);
        async_load_fence(tls_issue_cnt * (NumLdsStages - 1));
        __builtin_amdgcn_sched_barrier(0);

        // notify first tls load
        __builtin_amdgcn_sched_barrier(0);
        ebar_load_in_wg0.arrive();
        ebar_load_in_wg1.arrive();
        __builtin_amdgcn_sched_barrier(0);

        // producer loop func
        const auto producer_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto lds_stage = number<i % NumLdsStages>{};
            constexpr auto samp_idx  = number<(i + NumLdsStages) % FilterUnroll>{};

            constexpr bool is_last_loop = is_tail_loop && (i == LoopUnroll - 1);

            constexpr uint32_t waitcnt_in = is_tail_loop
                                                ? tls_issue_cnt * (NumLdsStages - lds_stage - 1)
                                                : tls_issue_cnt * (NumLdsStages - 1);

            // skip tls issue in tail loop
            if constexpr(!is_tail_loop)
            {
                // next tls load issue
                test_and_advance_tile_window(in_wg_dram_window, number<samp_idx>{});
                ebar_free_in.sync();
                async_tls_load_tile_asm(in_wg_lds_windows(lds_stage), in_wg_dram_window, samp_idx);

                // next mls load issue
                ebar_free_wei_wg0.sync();
                // isseu & track next mls load for wg0
                abars_wei_wg0[lds_stage].track();
                async_mls_bps_load_tile_asm(wei_wg0_lds_windows(lds_stage), wei_wg0_dram_window);
                abars_wei_wg0[lds_stage].arrive();

                ebar_free_wei_wg1.sync();
                // isseu & track next mls load for wg1
                abars_wei_wg1[lds_stage].track();
                async_mls_bps_load_tile_asm(wei_wg1_lds_windows(lds_stage), wei_wg1_dram_window);
                abars_wei_wg1[lds_stage].arrive();
            }

            if constexpr(!is_last_loop)
            {
                // wait in tls load
                __builtin_amdgcn_sched_barrier(0);
                async_load_fence(waitcnt_in);
                __builtin_amdgcn_sched_barrier(0);

                // notify in tls arrive
                __builtin_amdgcn_sched_barrier(0);
                ebar_load_in_wg0.arrive();
                ebar_load_in_wg1.arrive();
                __builtin_amdgcn_sched_barrier(0);
            }

            // TG sync
            __builtin_amdgcn_sched_barrier(0);
            wg_sync(bool_constant<true>{});
            __builtin_amdgcn_sched_barrier(0);
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

    // compute pipeline for compute wg0
    template <typename InWGLdsWindows, typename WeiWGLdsWindows, bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(InWGLdsWindows& in_wg_lds_windows,
                                   WeiWGLdsWindows& wei_wg_lds_windows,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>,
                                   number<0>) const
    {
        const auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        // init_and_sync abar
        static_for<0, NumLdsStages, 1>{}([&](auto i) { abars_wei_wg0[i].init_and_sync(0); });

        auto acc_block_tensor = blockwise_gemm.MakeAccBlockTile();

        // initialize acc tensor
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, acc_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // wait in tls load
        __builtin_amdgcn_sched_barrier(0);
        ebar_load_in_wg0.sync();
        __builtin_amdgcn_sched_barrier(0);

        // issue in ds read
        promote_prio();
        auto in_warp_tensors = blockwise_gemm.GetAWarpTensors(in_wg_lds_windows(number<0>{}));
        restore_prio();

        // wait wei mls load
        auto state    = abars_wei_wg0[number<0>{}].arrive();
        auto complete = 0;
        while(complete == 0)
        {
            complete = abars_wei_wg0[number<0>{}].test_wait(state);
        }

        // issue wei ds read
        promote_prio();
        auto wei_warp_tensors = blockwise_gemm.GetBWarpTensors(wei_wg_lds_windows(number<0>{}));
        restore_prio();

        const auto compute_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto lds_stage      = number<i % NumLdsStages>{};
            constexpr auto lds_stage_next = number<(lds_stage + 1) % NumLdsStages>{};

            constexpr bool is_last_loop = is_tail_loop && (i == LoopUnroll - 1);

            // lds wait
            lds_fence();

            if constexpr(!is_last_loop)
            {
                ebar_free_in.arrive();
                ebar_free_wei_wg0.arrive();
            }

            // issue mmac
            promote_prio();
            blockwise_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
            restore_prio();

            if constexpr(!is_last_loop)
            {
                // wait in tls load
                ebar_load_in_wg0.sync();

                // issue ds prefetch in
                promote_prio();
                in_warp_tensors = blockwise_gemm.GetAWarpTensors(in_wg_lds_windows(lds_stage_next));
                restore_prio();

                // wait wei mls load
                state    = abars_wei_wg0[lds_stage_next].arrive();
                complete = 0;
                while(complete == 0)
                {
                    complete = abars_wei_wg0[lds_stage_next].test_wait(state);
                }

                // issue ds prefetch wei
                promote_prio();
                wei_warp_tensors =
                    blockwise_gemm.GetBWarpTensors(wei_wg_lds_windows(lds_stage_next));
                restore_prio();
            }

            // TG sync
            __builtin_amdgcn_sched_barrier(0);
            wg_sync(bool_constant<true>{});
            __builtin_amdgcn_sched_barrier(0);
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

    // compute pipeline for compute wg1
    template <typename InWGLdsWindows, typename WeiWGLdsWindows, bool has_hot_loop>
    CK_TILE_DEVICE auto operator()(InWGLdsWindows& in_wg_lds_windows,
                                   WeiWGLdsWindows& wei_wg_lds_windows,
                                   index_t num_loop,
                                   bool_constant<has_hot_loop>,
                                   number<1>) const
    {
        const auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        // init_and_sync abar
        static_for<0, NumLdsStages, 1>{}([&](auto i) { abars_wei_wg0[i].init_and_sync(0); });

        auto acc_block_tensor = blockwise_gemm.MakeAccBlockTile();

        // initialize acc tensor
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, acc_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        const auto compute_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto lds_stage = number<i % NumLdsStages>{};

            // wait in tls load
            ebar_load_in_wg1.sync();

            // issue in ds read
            promote_prio();
            auto in_warp_tensors = blockwise_gemm.GetAWarpTensors(in_wg_lds_windows(lds_stage));
            restore_prio();

            // wait wei mls load
            auto state        = abars_wei_wg1[lds_stage].arrive();
            uint32_t complete = 0;
            while(complete == 0)
            {
                complete = abars_wei_wg1[lds_stage].test_wait(state);
            }

            // issue wei ds read
            promote_prio();
            auto wei_warp_tensors = blockwise_gemm.GetBWarpTensors(wei_wg_lds_windows(lds_stage));
            restore_prio();

            // wait lds
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            __builtin_amdgcn_sched_barrier(0);

            if constexpr(!is_tail_loop)
            {
                // notify producer that lds read is done
                ebar_free_in.arrive();
                ebar_free_wei_wg1.arrive();
            }

            // issue mmac
            promote_prio();
            blockwise_gemm(acc_block_tensor, in_warp_tensors, wei_warp_tensors);
            restore_prio();

            // TG sync
            __builtin_amdgcn_sched_barrier(0);
            wg_sync(bool_constant<true>{});
            __builtin_amdgcn_sched_barrier(0);
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

    // ebarriers
    hcu_ebarrier ebar_load_in_wg0;
    hcu_ebarrier ebar_load_in_wg1;
    hcu_ebarrier ebar_free_in;
    hcu_ebarrier ebar_free_wei_wg0;
    hcu_ebarrier ebar_free_wei_wg1;

    // abarriers
    array<hcu_abarrier, NumLdsStages> abars_wei_wg0;
    array<hcu_abarrier, NumLdsStages> abars_wei_wg1;
};

} // namespace ck_tile
