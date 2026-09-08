// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2023, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"

namespace ck {

template <index_t NumPrefetch, bool ALdsDirectLoad, bool BLdsDirectLoad>
struct MultiStageGemmPipeline_ConvRxS_v2r1s1
{
    template <bool v>
    using bool_constant = integral_constant<bool, v>;

    __host__ __device__ static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % NumPrefetch == 0;
    }

    __host__ __device__ static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / NumPrefetch) > 1;
    }

    template <bool HasMainKBlockLoop,
              typename BlockwiseGemm,
              typename AGridDesc,
              typename ABlockDesc,
              typename ABlockTransfer,
              typename AGridBuffer,
              typename ABlockBuffers,
              typename BGridDesc,
              typename BBlockDesc,
              typename B0BlockTransfer,
              typename B1BlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename C0ThreadBuffer,
              typename C1ThreadBuffer,
              bool ALdsDirectLoad_ = ALdsDirectLoad,
              bool BLdsDirectLoad_ = BLdsDirectLoad,
              typename std::enable_if<
                  std::is_same_v<bool_constant<ALdsDirectLoad_>, bool_constant<false>> &&
                      std::is_same_v<bool_constant<BLdsDirectLoad_>, bool_constant<false>>,
                  bool>::type = false>
    __device__ static void Run(BlockwiseGemm blockwise_gemm,
                               const AGridDesc& a_grid_desc,
                               const ABlockDesc& a_block_desc,
                               ABlockTransfer& a_blockwise_copy,
                               const AGridBuffer& a_grid_buf,
                               ABlockBuffers& a_block_bufs,
                               const BGridDesc& b_grid_desc,
                               const BBlockDesc& b_block_desc,
                               B0BlockTransfer& b0_blockwise_copy,
                               B1BlockTransfer& b1_blockwise_copy,
                               const BGridBuffer& b_grid_buf,
                               BBlockBuffers& b_block_bufs,
                               C0ThreadBuffer& c0_thread_buf,
                               C1ThreadBuffer& c1_thread_buf,
                               index_t num_loop)
    {
        // Load 0 ~ NumPrefetch - 2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
            b0_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
            b1_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});

            __builtin_amdgcn_sched_barrier(0);

            a_blockwise_copy.Advance();
            b0_blockwise_copy.Advance();
            b1_blockwise_copy.Advance();

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumPrefetch - 1
        a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<NumPrefetch - 1>{});
        b0_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<NumPrefetch - 1>{});
        b1_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<NumPrefetch - 1>{});
        __builtin_amdgcn_sched_barrier(0);

        // Initialize C
        c0_thread_buf.Clear();
        c1_thread_buf.Clear();

        // main body
        if constexpr(HasMainKBlockLoop)
        {
            index_t loop = 0;
            do
            {
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    // Wait i
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.LoadIssuePerStage * NumPrefetch -
                          blockwise_gemm.LoadIssueAB0>();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    // Lds store a, b0
                    a_blockwise_copy.RunWrite(
                        a_block_desc, a_block_bufs.At(Number<0>{}), Number<i>{});
                    b0_blockwise_copy.RunWrite(
                        b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    __builtin_amdgcn_sched_barrier(0);
                    a_blockwise_copy.Advance();
                    b0_blockwise_copy.Advance();
                    b1_blockwise_copy.Advance();
                    __builtin_amdgcn_sched_barrier(0);

                    // Wait until entire block is ready to read
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    blockwise_gemm.DsReadAB(a_block_bufs.At(Number<0>{}),
                                            b_block_bufs.At(Number<0>{}));

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // wave-synchronized mmac
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    // mmac A0, B0
                    blockwise_gemm.Mmac(c0_thread_buf);

                    // Load i+2
                    __builtin_amdgcn_sched_barrier(0);
                    a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
                    b0_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // Sync
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.LoadIssuePerStage*(NumPrefetch - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    // Lds store b1
                    b1_blockwise_copy.RunWrite(
                        b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // Wait until entire block is ready to read
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    blockwise_gemm.DsReadB(b_block_bufs.At(Number<0>{}));

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // wave-synchronized mmac
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    // mmac A0, B1
                    blockwise_gemm.Mmac(c1_thread_buf);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // Sync
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    b1_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
                });

                loop += NumPrefetch;

            } while(loop < num_loop - NumPrefetch);
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto i) {
                // Wait num_loop-i-NumPrefetch
                __builtin_amdgcn_sched_barrier(0);
                vmcnt<blockwise_gemm.LoadIssuePerStage*(NumPrefetch - i) -
                      blockwise_gemm.LoadIssueAB0>();
                __builtin_amdgcn_sched_barrier(0);

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // Lds store a, b0
                a_blockwise_copy.RunWrite(a_block_desc, a_block_bufs.At(Number<0>{}), Number<i>{});
                b0_blockwise_copy.RunWrite(b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                __builtin_amdgcn_sched_barrier(0);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // Lds load
                blockwise_gemm.DsReadAB(a_block_bufs.At(Number<0>{}), b_block_bufs.At(Number<0>{}));

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // wave-synchronized mmac
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // mmac a, b0
                blockwise_gemm.Mmac(c0_thread_buf);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // Sync
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // Wait num_loop-i-NumPrefetch
                __builtin_amdgcn_sched_barrier(0);
                vmcnt<blockwise_gemm.LoadIssuePerStage*(NumPrefetch - i - 1)>();
                __builtin_amdgcn_sched_barrier(0);

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // Lds store b1
                b1_blockwise_copy.RunWrite(b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                __builtin_amdgcn_sched_barrier(0);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // Wait until entire block is ready to read
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                blockwise_gemm.DsReadB(b_block_bufs.At(Number<0>{}));

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // wave-synchronized mmac
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // mmac A0, B1
                blockwise_gemm.Mmac(c1_thread_buf);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // Sync
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }
};

} // namespace ck
