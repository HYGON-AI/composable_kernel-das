// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/conv/warp/warp_gemm_dispatcher.hpp"
#include "ck_tile/ops/gemm/warp/warp_dsreadm_format_dispatcher.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_>
struct FusedConvIgemmPipelineTlsAgmemBgmemCregV1
{
    using Problem = remove_cvref_t<Problem_>;
    using Policy  = remove_cvref_t<Policy_>;

    using InElementwiseOp  = typename Problem::InElementwiseOp;
    using WeiElementwiseOp = typename Problem::WeiElementwiseOp;
    using OutElementwiseOp = typename Problem::OutElementwiseOp;

    static constexpr index_t NumLdsStages = Problem::NumLdsStages;
    static constexpr index_t FilterUnroll = Problem::FilterUnroll;
    static constexpr index_t LoopUnroll   = FilterUnroll * NumLdsStages;

    static constexpr index_t InVecLen  = Problem::InGmemLoadVecLen;
    static constexpr index_t WeiVecLen = Problem::WeiGmemLoadVecLen;
    static constexpr index_t OutVecLen = Problem::OutGmemStoreVecLen;

    static constexpr index_t NDimSpatial = Problem::NDimSpatial;

    static constexpr index_t BlockSize = Problem::BlockSize;

    CK_TILE_HOST_DEVICE static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % LoopUnroll == 0;
    }

    CK_TILE_HOST_DEVICE static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / LoopUnroll) > 1;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return Policy::template GetLdsByteSize<Problem>();
    }

    template <typename InTlsWindow,
              typename InLdsWindows,
              typename WeiTlsWindow,
              typename WeiLdsWindows,
              typename InElementwiseOp,
              typename WeiElementwiseOp,
              bool HasHotLoop>
    CK_TILE_DEVICE auto operator()(InTlsWindow& in_tls_window,
                                   InLdsWindows& in_lds_windows,
                                   const InElementwiseOp&,
                                   WeiTlsWindow& wei_tls_window,
                                   WeiLdsWindows& wei_lds_windows,
                                   const WeiElementwiseOp&,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        const auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto out_block_tensor = blockwise_gemm.MakeCBlockTile();

        // Load 0 ~ NumLdsStages - 2
        static_for<0, NumLdsStages - 1, 1>{}([&](auto i) {
            in_tls_window.async_tls_load_asm(in_lds_windows(i).get_buffer_ptr(), i);
            wei_tls_window.async_tls_load_asm(wei_lds_windows(i).get_buffer_ptr(), i);

            in_tls_window.test_and_advance(number<i + 1>{});
            wei_tls_window.test_and_advance(number<i + 1>{});
        });

        in_tls_window.async_tls_load_asm(
            in_lds_windows(number<NumLdsStages - 1>{}).get_buffer_ptr(),
            number<NumLdsStages - 1>{});
        wei_tls_window.async_tls_load_asm(
            wei_lds_windows(number<NumLdsStages - 1>{}).get_buffer_ptr(),
            number<NumLdsStages - 1>{});

        in_tls_window.test_and_advance(number<NumLdsStages>{});
        wei_tls_window.test_and_advance(number<NumLdsStages>{});

        // initialize out buffer
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // wait first
        __builtin_amdgcn_sched_barrier(0);
        async_load_fence((in_tls_window.get_num_of_access() + wei_tls_window.get_num_of_access()) *
                         (NumLdsStages - 1));
        __builtin_amdgcn_sched_barrier(0);

        wg_sync();

        // read first
        promote_prio();
        auto in_warp_tensors =
            blockwise_gemm.GetAWarpTensors(in_lds_windows(number<0>{}).get_buffer_ptr());
        auto wei_warp_tensors =
            blockwise_gemm.GetBWarpTensors(wei_lds_windows(number<0>{}).get_buffer_ptr());
        restore_prio();

        if constexpr(HasHotLoop)
        {
            index_t loop = 0;

            do
            {
                //  pipeline
                static_for<0, LoopUnroll, 1>{}([&](auto i) {
                    constexpr auto i_lds_stage = number<i % NumLdsStages>{};
                    constexpr auto samp_idx    = number<(i + NumLdsStages) % FilterUnroll>{};

                    // sync point 1
                    wg_sync_lds(bool_constant<true>{});

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    // sync point 2
                    wg_sync();

                    // Load i+2
                    in_tls_window.async_tls_load_asm(in_lds_windows(i_lds_stage).get_buffer_ptr(),
                                                     samp_idx);
                    wei_tls_window.async_tls_load_asm(wei_lds_windows(i_lds_stage).get_buffer_ptr(),
                                                      samp_idx);

                    in_tls_window.test_and_advance(number<samp_idx + 1>{});
                    wei_tls_window.test_and_advance(number<samp_idx + 1>{});

                    __builtin_amdgcn_sched_barrier(0);
                    async_load_fence(
                        (in_tls_window.get_num_of_access() + wei_tls_window.get_num_of_access()) *
                        (NumLdsStages - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    // sync point 3
                    wg_sync();

                    // lds prefetch
                    promote_prio();
                    in_warp_tensors = blockwise_gemm.GetAWarpTensors(
                        in_lds_windows(number<(i_lds_stage + 1) % NumLdsStages>{})
                            .get_buffer_ptr());
                    wei_warp_tensors = blockwise_gemm.GetBWarpTensors(
                        wei_lds_windows(number<(i_lds_stage + 1) % NumLdsStages>{})
                            .get_buffer_ptr());
                    restore_prio();
                });
                loop += LoopUnroll;
            } while(loop < (num_loop - LoopUnroll));
        }

        // tail
        {
            static_for<0, LoopUnroll, 1>{}([&](auto i) {
                constexpr auto i_lds_stage = number<i % NumLdsStages>{};
                constexpr auto samp_idx    = number<(i + NumLdsStages) % FilterUnroll>{};

                // sync point 1
                wg_sync_lds(bool_constant<true>{});

                // Mmac i
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();

                // sync point 2
                wg_sync();

                if constexpr(i < LoopUnroll - NumLdsStages)
                {
                    // Load i+2
                    in_tls_window.async_tls_load_asm(in_lds_windows(i_lds_stage).get_buffer_ptr(),
                                                     samp_idx);
                    wei_tls_window.async_tls_load_asm(wei_lds_windows(i_lds_stage).get_buffer_ptr(),
                                                      samp_idx);

                    in_tls_window.test_and_advance(number<samp_idx + 1>{});
                    wei_tls_window.test_and_advance(number<samp_idx + 1>{});

                    __builtin_amdgcn_sched_barrier(0);
                    async_load_fence(
                        (in_tls_window.get_num_of_access() + wei_tls_window.get_num_of_access()) *
                        (NumLdsStages - 1));
                    __builtin_amdgcn_sched_barrier(0);
                }
                else
                {
                    if constexpr(i != LoopUnroll - 1)
                    {
                        __builtin_amdgcn_sched_barrier(0);
                        if constexpr(NumLdsStages >= 3)
                        {
                            buffer_load_fence((in_tls_window.get_num_of_access() +
                                               wei_tls_window.get_num_of_access()) *
                                              (NumLdsStages - 2 - i));
                        }
                        else
                        {
                            buffer_load_fence(0);
                        }
                        __builtin_amdgcn_sched_barrier(0);
                    }
                }

                // sync point 3
                wg_sync();

                if constexpr(i < LoopUnroll - 1)
                {
                    // lds prefetch
                    promote_prio();
                    in_warp_tensors = blockwise_gemm.GetAWarpTensors(
                        in_lds_windows(number<(i_lds_stage + 1) % NumLdsStages>{})
                            .get_buffer_ptr());
                    wei_warp_tensors = blockwise_gemm.GetBWarpTensors(
                        wei_lds_windows(number<(i_lds_stage + 1) % NumLdsStages>{})
                            .get_buffer_ptr());
                    restore_prio();
                }
            });
        }

        return blockwise_gemm.MakeCBlockPermuteTile(out_block_tensor);
    }
};

} // namespace ck_tile
