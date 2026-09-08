// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2023, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"

namespace ck {

template <index_t NumPrefetch, bool ALdsDirectLoad, bool BLdsDirectLoad, index_t loop_remainder = 0>
struct MultiStageGemmPipeline_ConvRxS_v2r2s1
{
    template <bool v>
    using bool_constant = integral_constant<bool, v>;

    __host__ __device__ static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % (NumPrefetch) == 0;
    }

    __host__ __device__ static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / (NumPrefetch)) > 1;
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
              typename BBlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename CThreadBuffer,
              bool ALdsDirectLoad_ = ALdsDirectLoad,
              bool BLdsDirectLoad_ = BLdsDirectLoad,
              typename std::enable_if<
                  std::is_same_v<bool_constant<ALdsDirectLoad_>, bool_constant<false>> &&
                      std::is_same_v<bool_constant<BLdsDirectLoad_>, bool_constant<false>>,
                  bool>::type = false>
    __device__ static void RunWG0(BlockwiseGemm blockwise_gemm,
                                  const AGridDesc& a_grid_desc,
                                  const ABlockDesc& a_block_desc,
                                  ABlockTransfer& a_blockwise_copy,
                                  const AGridBuffer& a_grid_buf,
                                  ABlockBuffers& a_block_bufs,
                                  const BGridDesc& b_grid_desc,
                                  const BBlockDesc& b_block_desc,
                                  BBlockTransfer& b_blockwise_copy,
                                  const BGridBuffer& b_grid_buf,
                                  BBlockBuffers& b_block_bufs,
                                  CThreadBuffer& c_thread_buf,
                                  index_t num_loop)
    {
        // Load 0 ~ NumPrefetch - 2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
            b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});

            __builtin_amdgcn_sched_barrier(0);

            a_blockwise_copy.Advance();
            b_blockwise_copy.Advance();

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumPrefetch - 1
        a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<NumPrefetch - 1>{});
        b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<NumPrefetch - 1>{});
        __builtin_amdgcn_sched_barrier(0);

        // Initialize C
        c_thread_buf.Clear();

        // sync point 1
        __builtin_amdgcn_sched_barrier(0);
        __builtin_amdgcn_s_barrier();
        __builtin_amdgcn_sched_barrier(0);

        // main body
        if constexpr(HasMainKBlockLoop)
        {
            index_t loop = 0;
            do
            {
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumPrefetch - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumPrefetch - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    // Lds store
                    a_blockwise_copy.RunWrite(
                        a_block_desc, a_block_bufs.At(Number<0>{}), Number<i>{});
                    b_blockwise_copy.RunWrite(
                        b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    __builtin_amdgcn_sched_barrier(0);
                    a_blockwise_copy.Advance();
                    b_blockwise_copy.Advance();
                    __builtin_amdgcn_sched_barrier(0);

                    // Wait until entire block is ready to read
                    // sync point 2
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

                    // Load i+2
                    __builtin_amdgcn_sched_barrier(0);
                    a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
                    b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // wave-synchronized mmac
                    // sync point 3
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    blockwise_gemm.Mmac(c_thread_buf);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // sync point 4
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_barrier();
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
                vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumPrefetch - 1 - i)>();
                __builtin_amdgcn_sched_barrier(0);

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // Lds store
                a_blockwise_copy.RunWrite(a_block_desc, a_block_bufs.At(Number<0>{}), Number<i>{});
                b_blockwise_copy.RunWrite(b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                __builtin_amdgcn_sched_barrier(0);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // sync point 1
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
                // sync point 2
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                blockwise_gemm.Mmac(c_thread_buf);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // sync point 3
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }

    template <bool HasMainKBlockLoop,
              typename BlockwiseGemm,
              typename ABlockBuffers,
              typename BGridDesc,
              typename BBlockDesc,
              typename BBlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename CThreadBuffer,
              bool ALdsDirectLoad_ = ALdsDirectLoad,
              bool BLdsDirectLoad_ = BLdsDirectLoad,
              typename std::enable_if<
                  std::is_same_v<bool_constant<ALdsDirectLoad_>, bool_constant<false>> &&
                      std::is_same_v<bool_constant<BLdsDirectLoad_>, bool_constant<false>>,
                  bool>::type = false>
    __device__ static void RunWG1(BlockwiseGemm blockwise_gemm,
                                  ABlockBuffers& a_block_bufs,
                                  const BGridDesc& b_grid_desc,
                                  const BBlockDesc& b_block_desc,
                                  BBlockTransfer& b_blockwise_copy,
                                  const BGridBuffer& b_grid_buf,
                                  BBlockBuffers& b_block_bufs,
                                  CThreadBuffer& c_thread_buf,
                                  index_t num_loop)
    {
        // sync point 1
        __builtin_amdgcn_sched_barrier(0);
        __builtin_amdgcn_s_barrier();
        __builtin_amdgcn_sched_barrier(0);

        // Load 0 ~ NumPrefetch - 2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
            __builtin_amdgcn_sched_barrier(0);

            b_blockwise_copy.Advance();
            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumPrefetch - 1
        b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<NumPrefetch - 1>{});
        __builtin_amdgcn_sched_barrier(0);

        // Initialize C
        c_thread_buf.Clear();

        // main body
        if constexpr(HasMainKBlockLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumPrefetch - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssueB*(NumPrefetch - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    // Lds store
                    b_blockwise_copy.RunWrite(
                        b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // sync point 2
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    __builtin_amdgcn_sched_barrier(0);
                    b_blockwise_copy.Advance();
                    __builtin_amdgcn_sched_barrier(0);

                    // Wait until entire block is ready to read
                    // sync point 3
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
                    // sync point 4
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // promote wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(1);
                    __builtin_amdgcn_sched_barrier(0);

                    blockwise_gemm.Mmac(c_thread_buf);

                    // Load i+2
                    __builtin_amdgcn_sched_barrier(0);
                    b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);

                    // restore wave priority
                    __builtin_amdgcn_sched_barrier(0);
                    __builtin_amdgcn_s_setprio(0);
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
                vmcnt<blockwise_gemm.DirectLoadIssueB*(NumPrefetch - 1 - i)>();
                __builtin_amdgcn_sched_barrier(0);

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                // Lds store
                b_blockwise_copy.RunWrite(b_block_desc, b_block_bufs.At(Number<0>{}), Number<i>{});
                __builtin_amdgcn_sched_barrier(0);

                // sync point 1
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);

                // sync point 2
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
                // sync point 3
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();

                // promote wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(1);
                __builtin_amdgcn_sched_barrier(0);

                blockwise_gemm.Mmac(c_thread_buf);

                // restore wave priority
                __builtin_amdgcn_sched_barrier(0);
                __builtin_amdgcn_s_setprio(0);
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }
};

} // namespace ck
