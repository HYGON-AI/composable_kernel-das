// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2023, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/common_header.hpp"

namespace ck {

template <index_t NumGemmKPrefetchStage, bool ALdsDirectLoad = true, bool BLdsDirectLoad = true>
struct MultiStageGemmPipeline_v1;

template <index_t NumGemmKPrefetchStage>
struct MultiStageGemmPipeline_v1<NumGemmKPrefetchStage, true, true>
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
              typename BlockwiseGemm,
              typename AGridDesc,
              typename ABlockDesc,
              typename ABlockTransfer,
              typename AGridBuffer,
              typename ABlockBuffers,
              typename ABlockTransferStep,
              typename BGridDesc,
              typename BBlockDesc,
              typename BBlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename BBlockTransferStep,
              typename CThreadBuffer>
    __device__ static void Run(BlockwiseGemm blockwise_gemm,
                               const AGridDesc& a_grid_desc,
                               const ABlockDesc& a_block_desc,
                               ABlockTransfer& a_blockwise_copy,
                               const AGridBuffer& a_grid_buf,
                               ABlockBuffers& a_block_bufs,
                               const ABlockTransferStep& a_block_copy_step,
                               const BGridDesc& b_grid_desc,
                               const BBlockDesc& b_block_desc,
                               BBlockTransfer& b_blockwise_copy,
                               const BGridBuffer& b_grid_buf,
                               BBlockBuffers& b_block_bufs,
                               const BBlockTransferStep& b_block_copy_step,
                               CThreadBuffer& c_thread_buf,
                               index_t num_loop)
    {
        // Load 0 ~ NumGemmKPrefetchStage - 2
        static_for<0, NumGemmKPrefetchStage - 1, 1>{}([&](auto i) {
            a_blockwise_copy.Run(
                a_grid_desc, a_grid_buf, a_block_desc, a_block_bufs.At(Number<i>{}));
            b_blockwise_copy.Run(
                b_grid_desc, b_grid_buf, b_block_desc, b_block_bufs.At(Number<i>{}));

            __builtin_amdgcn_sched_barrier(0);

            a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
            b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumGemmKPrefetchStage - 1
        a_blockwise_copy.Run(a_grid_desc,
                             a_grid_buf,
                             a_block_desc,
                             a_block_bufs.At(Number<NumGemmKPrefetchStage - 1>{}));
        b_blockwise_copy.Run(b_grid_desc,
                             b_grid_buf,
                             b_block_desc,
                             b_block_bufs.At(Number<NumGemmKPrefetchStage - 1>{}));
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
                static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    block_sync_vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage -
                                                                             1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Read i
                    blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}),
                                            b_block_bufs.At(Number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
                    b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_sched_barrier(0);

                    // Mmac i
                    blockwise_gemm.Mmac(c_thread_buf);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Load i+2
                    a_blockwise_copy.Run(
                        a_grid_desc, a_grid_buf, a_block_desc, a_block_bufs.At(Number<i>{}));
                    b_blockwise_copy.Run(
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
                block_sync_vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1 -
                                                                         i)>();
                __builtin_amdgcn_sched_barrier(0);

                // Read num_loop-i-NumGemmKPrefetchStage
                blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}), b_block_bufs.At(Number<i>{}));
                __builtin_amdgcn_sched_barrier(0);

                // Mmac num_loop-i-NumGemmKPrefetchStage-2
                blockwise_gemm.Mmac(c_thread_buf);
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }
};

template <index_t NumGemmKPrefetchStage>
struct MultiStageGemmPipeline_v1<NumGemmKPrefetchStage, true, false>
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
              typename BlockwiseGemm,
              typename AGridDesc,
              typename ABlockDesc,
              typename ABlockTransfer,
              typename AGridBuffer,
              typename ABlockBuffers,
              typename ABlockTransferStep,
              typename BGridDesc,
              typename BBlockDesc,
              typename BBlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename BBlockTransferStep,
              typename CThreadBuffer>
    __device__ static void Run(BlockwiseGemm blockwise_gemm,
                               const AGridDesc& a_grid_desc,
                               const ABlockDesc& a_block_desc,
                               ABlockTransfer& a_blockwise_copy,
                               const AGridBuffer& a_grid_buf,
                               ABlockBuffers& a_block_bufs,
                               const ABlockTransferStep& a_block_copy_step,
                               const BGridDesc& b_grid_desc,
                               const BBlockDesc& b_block_desc,
                               BBlockTransfer& b_blockwise_copy,
                               const BGridBuffer& b_grid_buf,
                               BBlockBuffers& b_block_bufs,
                               const BBlockTransferStep& b_block_copy_step,
                               CThreadBuffer& c_thread_buf,
                               index_t num_loop)
    {
        // Load 0 ~ NumGemmKPrefetchStage - 2
        static_for<0, NumGemmKPrefetchStage - 1, 1>{}([&](auto i) {
            a_blockwise_copy.Run(
                a_grid_desc, a_grid_buf, a_block_desc, a_block_bufs.At(Number<i>{}));
            b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});

            __builtin_amdgcn_sched_barrier(0);

            a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
            b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumGemmKPrefetchStage - 1
        a_blockwise_copy.Run(a_grid_desc,
                             a_grid_buf,
                             a_block_desc,
                             a_block_bufs.At(Number<NumGemmKPrefetchStage - 1>{}));
        b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<NumGemmKPrefetchStage - 1>{});
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
                static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                    // Wait A
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssuePerStage * NumGemmKPrefetchStage -
                          blockwise_gemm.DirectLoadIssueA>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Wait B
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Write B to LDS
                    b_blockwise_copy.RunWrite(
                        b_block_desc, b_block_bufs.At(Number<i>{}), Number<i>{});

                    __builtin_amdgcn_sched_barrier(0);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Read i
                    blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}),
                                            b_block_bufs.At(Number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
                    b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // Mmac i
                    blockwise_gemm.Mmac(c_thread_buf);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Load i+2
                    a_blockwise_copy.Run(
                        a_grid_desc, a_grid_buf, a_block_desc, a_block_bufs.At(Number<i>{}));
                    b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
                    __builtin_amdgcn_sched_barrier(0);
                });

                loop += NumGemmKPrefetchStage;

            } while(loop < num_loop - NumGemmKPrefetchStage);
        }

        // tail
        {
            static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                // Wait num_loop-i-NumGemmKPrefetchStage
                // Wait A
                __builtin_amdgcn_sched_barrier(0);
                vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - i) -
                      blockwise_gemm.DirectLoadIssueA>();
                __builtin_amdgcn_sched_barrier(0);

                // Wait B
                __builtin_amdgcn_sched_barrier(0);
                vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - i - 1)>();
                __builtin_amdgcn_sched_barrier(0);

                // Write B to LDS
                b_blockwise_copy.RunWrite(b_block_desc, b_block_bufs.At(Number<i>{}), Number<i>{});

                __builtin_amdgcn_sched_barrier(0);

                // Sync with other waves to avoid data hazard
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // Read num_loop-i-NumGemmKPrefetchStage
                blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}), b_block_bufs.At(Number<i>{}));
                __builtin_amdgcn_sched_barrier(0);

                // Mmac num_loop-i-NumGemmKPrefetchStage-2
                blockwise_gemm.Mmac(c_thread_buf);
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }
};

template <index_t NumGemmKPrefetchStage>
struct MultiStageGemmPipeline_v1<NumGemmKPrefetchStage, false, true>
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
              typename BlockwiseGemm,
              typename AGridDesc,
              typename ABlockDesc,
              typename ABlockTransfer,
              typename AGridBuffer,
              typename ABlockBuffers,
              typename ABlockTransferStep,
              typename BGridDesc,
              typename BBlockDesc,
              typename BBlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename BBlockTransferStep,
              typename CThreadBuffer>
    __device__ static void Run(BlockwiseGemm blockwise_gemm,
                               const AGridDesc& a_grid_desc,
                               const ABlockDesc& a_block_desc,
                               ABlockTransfer& a_blockwise_copy,
                               const AGridBuffer& a_grid_buf,
                               ABlockBuffers& a_block_bufs,
                               const ABlockTransferStep& a_block_copy_step,
                               const BGridDesc& b_grid_desc,
                               const BBlockDesc& b_block_desc,
                               BBlockTransfer& b_blockwise_copy,
                               const BGridBuffer& b_grid_buf,
                               BBlockBuffers& b_block_bufs,
                               const BBlockTransferStep& b_block_copy_step,
                               CThreadBuffer& c_thread_buf,
                               index_t num_loop)
    {
        // Load 0 ~ NumGemmKPrefetchStage - 2
        static_for<0, NumGemmKPrefetchStage - 1, 1>{}([&](auto i) {
            a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
            b_blockwise_copy.Run(
                b_grid_desc, b_grid_buf, b_block_desc, b_block_bufs.At(Number<i>{}));
            __builtin_amdgcn_sched_barrier(0);

            a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
            b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumGemmKPrefetchStage - 1
        a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<NumGemmKPrefetchStage - 1>{});
        b_blockwise_copy.Run(b_grid_desc,
                             b_grid_buf,
                             b_block_desc,
                             b_block_bufs.At(Number<NumGemmKPrefetchStage - 1>{}));
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
                static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                    // Wait A
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssuePerStage * NumGemmKPrefetchStage -
                          blockwise_gemm.DirectLoadIssueA>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Write A to LDS
                    a_blockwise_copy.RunWrite(
                        a_block_desc, a_block_bufs.At(Number<i>{}), Number<i>{});

                    // Wait B
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Read i
                    blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}),
                                            b_block_bufs.At(Number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
                    b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // Mmac i
                    blockwise_gemm.Mmac(c_thread_buf);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Load i+2
                    a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
                    b_blockwise_copy.Run(
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
                vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - i) -
                      blockwise_gemm.DirectLoadIssueA>();
                __builtin_amdgcn_sched_barrier(0);

                // Write A to LDS
                a_blockwise_copy.RunWrite(a_block_desc, a_block_bufs.At(Number<i>{}), Number<i>{});

                // Wait B
                __builtin_amdgcn_sched_barrier(0);
                vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - i - 1)>();
                __builtin_amdgcn_sched_barrier(0);

                // Sync with other waves to avoid data hazard
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // Read num_loop-i-NumGemmKPrefetchStage
                blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}), b_block_bufs.At(Number<i>{}));
                __builtin_amdgcn_sched_barrier(0);

                // Mmac num_loop-i-NumGemmKPrefetchStage-2
                blockwise_gemm.Mmac(c_thread_buf);
                __builtin_amdgcn_sched_barrier(0);
            });
        }
    }
};

template <index_t NumGemmKPrefetchStage>
struct MultiStageGemmPipeline_v1<NumGemmKPrefetchStage, false, false>
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
              typename BlockwiseGemm,
              typename AGridDesc,
              typename ABlockDesc,
              typename ABlockTransfer,
              typename AGridBuffer,
              typename ABlockBuffers,
              typename ABlockTransferStep,
              typename BGridDesc,
              typename BBlockDesc,
              typename BBlockTransfer,
              typename BGridBuffer,
              typename BBlockBuffers,
              typename BBlockTransferStep,
              typename CThreadBuffer>
    __device__ static void Run(BlockwiseGemm blockwise_gemm,
                               const AGridDesc& a_grid_desc,
                               const ABlockDesc& a_block_desc,
                               ABlockTransfer& a_blockwise_copy,
                               const AGridBuffer& a_grid_buf,
                               ABlockBuffers& a_block_bufs,
                               const ABlockTransferStep& a_block_copy_step,
                               const BGridDesc& b_grid_desc,
                               const BBlockDesc& b_block_desc,
                               BBlockTransfer& b_blockwise_copy,
                               const BGridBuffer& b_grid_buf,
                               BBlockBuffers& b_block_bufs,
                               const BBlockTransferStep& b_block_copy_step,
                               CThreadBuffer& c_thread_buf,
                               index_t num_loop)
    {
        // Load 0 ~ NumGemmKPrefetchStage - 2
        static_for<0, NumGemmKPrefetchStage - 1, 1>{}([&](auto i) {
            a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
            b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});

            __builtin_amdgcn_sched_barrier(0);

            a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
            b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);

            __builtin_amdgcn_sched_barrier(0);
        });

        // Load NumGemmKPrefetchStage - 1
        a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<NumGemmKPrefetchStage - 1>{});
        b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<NumGemmKPrefetchStage - 1>{});
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
                static_for<0, NumGemmKPrefetchStage, 1>{}([&](auto i) {
                    // Wait i, inflight load is always
                    // DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)
                    __builtin_amdgcn_sched_barrier(0);
                    vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1)>();
                    __builtin_amdgcn_sched_barrier(0);

                    // Write to LDS
                    a_blockwise_copy.RunWrite(
                        a_block_desc, a_block_bufs.At(Number<i>{}), Number<i>{});
                    b_blockwise_copy.RunWrite(
                        b_block_desc, b_block_bufs.At(Number<i>{}), Number<i>{});

                    __builtin_amdgcn_sched_barrier(0);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Read i
                    blockwise_gemm.DsReadAB(a_block_bufs.At(Number<i>{}),
                                            b_block_bufs.At(Number<i>{}));
                    __builtin_amdgcn_sched_barrier(0);

                    // Move to i+2
                    a_blockwise_copy.MoveSrcSliceWindow(a_grid_desc, a_block_copy_step);
                    b_blockwise_copy.MoveSrcSliceWindow(b_grid_desc, b_block_copy_step);
                    __builtin_amdgcn_sched_barrier(0);

                    __builtin_amdgcn_s_waitcnt(0xc07f);
                    __builtin_amdgcn_s_barrier();

                    // Mmac i
                    blockwise_gemm.Mmac(c_thread_buf);

                    // Sync with other waves to avoid data hazard
                    __builtin_amdgcn_s_barrier();
                    __builtin_amdgcn_sched_barrier(0);

                    // Load i+2
                    a_blockwise_copy.RunRead(a_grid_desc, a_grid_buf, Number<i>{});
                    b_blockwise_copy.RunRead(b_grid_desc, b_grid_buf, Number<i>{});
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
                vmcnt<blockwise_gemm.DirectLoadIssuePerStage*(NumGemmKPrefetchStage - 1 - i)>();
                __builtin_amdgcn_sched_barrier(0);

                // Write to LDS
                a_blockwise_copy.RunWrite(a_block_desc, a_block_bufs.At(Number<i>{}), Number<i>{});
                b_blockwise_copy.RunWrite(b_block_desc, b_block_bufs.At(Number<i>{}), Number<i>{});
                __builtin_amdgcn_sched_barrier(0);

                // Sync with other waves to avoid data hazard
                __builtin_amdgcn_s_waitcnt(0xc07f);
                __builtin_amdgcn_s_barrier();
                __builtin_amdgcn_sched_barrier(0);

                // Read num_loop-i-NumGemmKPrefetchStage
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
