// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2023, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"

namespace ck {

template <index_t NumGemmKPrefetchStage, index_t DirectLoadIssuePerStage>
struct MultiStageWaveletPipeline
{
    __host__ __device__ static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % NumGemmKPrefetchStage == 0;
    }

    __host__ __device__ static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / NumGemmKPrefetchStage) > 1;
    }

    template <bool HasMainKBlockLoop,
              typename AGridDesc,
              typename ABlockDesc,
              typename ABlockCopy,
              typename AGridBuf,
              typename ABlockBufs,
              typename ABlockCopyStep,
              typename BGridDesc,
              typename BBlockDesc,
              typename BBlockCopy,
              typename BGridBuf,
              typename BBlockBufs,
              typename BBlockCopyStep>
    __device__ static void RunLoadPipeline(const AGridDesc& a_grid_desc,
                                           const ABlockDesc& a_block_desc,
                                           ABlockCopy& a_block_copy,
                                           const AGridBuf& a_grid_buf,
                                           ABlockBufs& a_block_bufs,
                                           const ABlockCopyStep& a_block_copy_step,
                                           const BGridDesc& b_grid_desc,
                                           const BBlockDesc& b_block_desc,
                                           BBlockCopy& b_block_copy,
                                           const BGridBuf& b_grid_buf,
                                           BBlockBufs& b_block_bufs,
                                           const BBlockCopyStep& b_block_copy_step,
                                           index_t num_loop)
    {
        // Load 0 ~ NumGemmKPrefetchStage - 2
        static_for<0, NumGemmKPrefetchStage - 1, 1>{}([&](auto i) {
            a_block_copy.Run(a_grid_desc, a_grid_buf, a_block_desc, a_block_bufs.At(Number<i>{}));
            b_block_copy.Run(b_grid_desc, b_grid_buf, b_block_desc, b_block_bufs.At(Number<i>{}));

            __builtin_amdgcn_sched_barrier(0);

            a_block_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
            b_block_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumGemmKPrefetchStage - 1
        a_block_copy.Run(a_grid_desc,
                         a_grid_buf,
                         a_block_desc,
                         a_block_bufs.At(Number<NumGemmKPrefetchStage - 1>{}));
        b_block_copy.Run(b_grid_desc,
                         b_grid_buf,
                         b_block_desc,
                         b_block_bufs.At(Number<NumGemmKPrefetchStage - 1>{}));
        __builtin_amdgcn_sched_barrier(0);

        // main body
        if constexpr(HasMainKBlockLoop)
        {
            index_t loop = 0;
            do
            {
                static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    block_sync_vmcnt<DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    a_block_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
                    b_block_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);
                    __builtin_amdgcn_sched_barrier(0);

                    // math waves: dsread

                    // sync with math waves
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // math waves: mmac

                    // sync with math waves
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Issue load i+2
                    a_block_copy.Run(
                        a_grid_desc, a_grid_buf, a_block_desc, a_block_bufs.At(Number<i>{}));
                    b_block_copy.Run(
                        b_grid_desc, b_grid_buf, b_block_desc, b_block_bufs.At(Number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);
                });

                loop += NumGemmKPrefetchStage;
            } while(loop < num_loop - NumGemmKPrefetchStage);
        }

        // tail
        {
            static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                // Wait num_loop-i-NumGemmKPrefetchStage
                __builtin_amdgcn_sched_barrier(0);
                block_sync_vmcnt<DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1 - i)>();
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }

    template <bool HasMainKBlockLoop,
              typename BlockwiseGemm,
              typename ABlockBufs,
              typename BBlockBufs,
              typename CThreadBuffer>
    __device__ static void RunMathPipeline(BlockwiseGemm& blockwise_gemm,
                                           const ABlockBufs& a_block_bufs,
                                           const BBlockBufs& b_block_bufs,
                                           CThreadBuffer& c_thread_buf,
                                           index_t num_loop)
    {
        // main body
        if constexpr(HasMainKBlockLoop)
        {
            index_t loop = 0;
            do
            {
                // math pipeline
                static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                    // load waves: wait vmcnt

                    // sync with load waves
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}),
                                            b_block_bufs.At(Number<i>{}));

                    __builtin_amdgcn_sched_barrier(0);

                    // sync with load waves
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Mmac i
                    blockwise_gemm.Mmac(c_thread_buf);
                    __builtin_amdgcn_sched_barrier(0);

                    // sync with load waves
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // load waves: issue next load
                });

                loop += NumGemmKPrefetchStage;
            } while(loop < num_loop - NumGemmKPrefetchStage);
        }

        // tail
        {
            static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                // sync with load waves
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}), b_block_bufs.At(Number<i>{}));

                __builtin_amdgcn_sched_barrier(0);

                // Mmac num_loop-i-NumGemmKPrefetchStage-2
                blockwise_gemm.Mmac(c_thread_buf);
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }
};

} // namespace ck
