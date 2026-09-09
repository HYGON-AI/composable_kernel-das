// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_>
struct FusedConvIgemmPipelineWaspAgmemBgmemCregV1
{
    using Problem = remove_cvref_t<Problem_>;
    using Policy  = remove_cvref_t<Policy_>;

    using InDataType  = remove_cvref_t<typename Problem::InDataType>;
    using WeiDataType = remove_cvref_t<typename Problem::WeiDataType>;
    using OutDataType = remove_cvref_t<typename Problem::OutDataType>;

    using InLayout  = remove_cvref_t<typename Problem::InLayout>;
    using WeiLayout = remove_cvref_t<typename Problem::WeiLayout>;
    using OutLayout = remove_cvref_t<typename Problem::OutLayout>;

    using InElementwiseOp  = typename Problem::InElementwiseOp;
    using WeiElementwiseOp = typename Problem::WeiElementwiseOp;
    using OutElementwiseOp = typename Problem::OutElementwiseOp;

    static constexpr index_t NDimSpatial = Problem::NDimSpatial;

    static constexpr index_t MPerWG    = Problem::MPerWG;
    static constexpr index_t NPerWG    = Problem::NPerWG;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t BlockSize = Problem::BlockSize;

    static constexpr index_t NumPrefetch = Problem::NumPrefetch;

    static constexpr index_t InVecLen  = Problem::InGmemLoadVecLen;
    static constexpr index_t WeiVecLen = Problem::WeiGmemLoadVecLen;
    static constexpr index_t OutVecLen = Problem::OutGmemStoreVecLen;

    static constexpr index_t MWGs = Problem::MWGs;
    static constexpr index_t NWGs = Problem::NWGs;

    CK_TILE_HOST_DEVICE static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % NumPrefetch == 0;
    }

    CK_TILE_HOST_DEVICE static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / NumPrefetch) > 1;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return Policy::template GetLdsByteSize<Problem>();
    }

    template <typename InCopyDramWindow,
              typename WeiCopyDramWindow,
              typename InCopyLdsWindow,
              typename WeiCopyLdsWindow,
              typename InGemmLdsWindow,
              typename WeiGemmLdsWindow,
              typename InElementwiseOp,
              typename WeiElementwiseOp,
              bool HasHotLoop>
    CK_TILE_DEVICE auto operator()(InCopyDramWindow& in_copy_dram_window,
                                   InCopyLdsWindow& in_copy_lds_window,
                                   const InGemmLdsWindow& in_gemm_lds_window,
                                   const InElementwiseOp& in_elem_op,
                                   WeiCopyDramWindow& wei_copy_dram_window,
                                   WeiCopyLdsWindow& wei_copy_lds_window,
                                   const WeiGemmLdsWindow& wei_gemm_lds_window,
                                   const WeiElementwiseOp& wei_elem_op,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto out_block_tensor = blockwise_gemm.MakeOutBlockTile();

        statically_indexed_array<decltype(load_tile_by_inline_asm(in_copy_dram_window)),
                                 NumPrefetch>
            in_tmp_buffers;
        statically_indexed_array<decltype(load_tile_by_inline_asm(wei_copy_dram_window)),
                                 NumPrefetch>
            wei_tmp_buffers;

        // Load 0 ~ NumPrefetch - 2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(in_tmp_buffers(number<i>{}), in_copy_dram_window);
            load_tile_by_inline_asm(wei_tmp_buffers(number<i>{}), wei_copy_dram_window);

            advance_tile(in_copy_dram_window);
            advance_tile(wei_copy_dram_window);
        });

        // Load NumPrefetch - 1
        load_tile_by_inline_asm(in_tmp_buffers(number<NumPrefetch - 1>{}), in_copy_dram_window);
        load_tile_by_inline_asm(wei_tmp_buffers(number<NumPrefetch - 1>{}), wei_copy_dram_window);

        // initialize out buffer
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);

        // sync point 1
        wg_sync();

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence((in_copy_dram_window.get_num_of_access() +
                                       wei_copy_dram_window.get_num_of_access()) *
                                      (NumPrefetch - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    tile_elementwise_inout(
                        in_elem_op, in_tmp_buffers(number<i>{}), in_tmp_buffers(number<i>{}));
                    tile_elementwise_inout(
                        wei_elem_op, wei_tmp_buffers(number<i>{}), wei_tmp_buffers(number<i>{}));

                    // Write to LDS
                    promote_prio();
                    store_tile(
                        in_copy_lds_window, in_tmp_buffers[number<i>{}], bool_constant<true>{});
                    store_tile(
                        wei_copy_lds_window, wei_tmp_buffers[number<i>{}], bool_constant<true>{});
                    restore_prio();

                    advance_tile(in_copy_dram_window);
                    advance_tile(wei_copy_dram_window);

                    // sync point 2
                    wg_sync_lds();

                    // Read i
                    promote_prio();
                    const auto in_warp_tensors  = blockwise_gemm.LdsLoadIn(in_gemm_lds_window);
                    const auto wei_warp_tensors = blockwise_gemm.LdsLoadWei(wei_gemm_lds_window);
                    restore_prio();

                    // Load i+2
                    load_tile_by_inline_asm(in_tmp_buffers(number<i>{}), in_copy_dram_window);
                    load_tile_by_inline_asm(wei_tmp_buffers(number<i>{}), wei_copy_dram_window);

                    // sync point 3
                    wg_sync_lds();

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    // sync point 4
                    wg_sync();
                });

                loop += NumPrefetch;
            } while(loop < num_loop - NumPrefetch);
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto i) {
                __builtin_amdgcn_sched_barrier(0);
                buffer_load_fence((in_copy_dram_window.get_num_of_access() +
                                   wei_copy_dram_window.get_num_of_access()) *
                                  (NumPrefetch - 1 - i));
                __builtin_amdgcn_sched_barrier(0);

                tile_elementwise_inout(
                    in_elem_op, in_tmp_buffers(number<i>{}), in_tmp_buffers(number<i>{}));
                tile_elementwise_inout(
                    wei_elem_op, wei_tmp_buffers(number<i>{}), wei_tmp_buffers(number<i>{}));

                // Write to LDS
                promote_prio();
                store_tile(in_copy_lds_window, in_tmp_buffers[number<i>{}], bool_constant<true>{});
                store_tile(
                    wei_copy_lds_window, wei_tmp_buffers[number<i>{}], bool_constant<true>{});
                restore_prio();

                // sync point 5
                wg_sync_lds();

                // Read num_loop-i-NumPrefetch
                promote_prio();
                const auto in_warp_tensors  = blockwise_gemm.LdsLoadIn(in_gemm_lds_window);
                const auto wei_warp_tensors = blockwise_gemm.LdsLoadWei(wei_gemm_lds_window);
                restore_prio();

                // sync point 6
                wg_sync_lds();

                // Mmac num_loop-i-NumPrefetch-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();

                // sync point 7
                wg_sync();
            });
        }

        return out_block_tensor;
    }

    template <typename InCopyDramWindow,
              typename InCopyLdsWindow,
              typename InGemmLdsWindow,
              typename WeiGemmLdsWindow,
              typename InElementwiseOp,
              bool HasHotLoop,
              index_t MWGs_                       = MWGs,
              index_t NWGs_                       = NWGs,
              typename std::enable_if<std::is_same_v<number<MWGs_>, number<2>> &&
                                          std::is_same_v<number<NWGs_>, number<1>>,
                                      bool>::type = false>
    CK_TILE_DEVICE auto operator()(InCopyDramWindow& in_copy_dram_window,
                                   InCopyLdsWindow& in_copy_lds_window,
                                   const InGemmLdsWindow& in_gemm_lds_window,
                                   const InElementwiseOp& in_elem_op,
                                   const WeiGemmLdsWindow& wei_gemm_lds_window,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto out_block_tensor = blockwise_gemm.MakeOutBlockTile();

        // initialize out buffer
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);

        // sync point 1
        wg_sync();

        statically_indexed_array<decltype(load_tile_by_inline_asm(in_copy_dram_window)),
                                 NumPrefetch>
            in_tmp_buffers;

        // Load 0 ~ NumPrefetch -2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(in_tmp_buffers(number<i>{}), in_copy_dram_window);
            advance_tile(in_copy_dram_window);
        });

        // Load NumPrefetch - 1
        load_tile_by_inline_asm(in_tmp_buffers(number<NumPrefetch - 1>{}), in_copy_dram_window);

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(in_copy_dram_window.get_num_of_access() * (NumPrefetch - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    tile_elementwise_inout(
                        in_elem_op, in_tmp_buffers(number<i>{}), in_tmp_buffers(number<i>{}));

                    // Write to LDS
                    promote_prio();
                    store_tile(
                        in_copy_lds_window, in_tmp_buffers[number<i>{}], bool_constant<true>{});
                    restore_prio();

                    // sync point 2
                    wg_sync();

                    advance_tile(in_copy_dram_window);

                    // sync point 3
                    wg_sync_lds();

                    // Read i
                    promote_prio();
                    const auto in_warp_tensors  = blockwise_gemm.LdsLoadIn(in_gemm_lds_window);
                    const auto wei_warp_tensors = blockwise_gemm.LdsLoadWei(wei_gemm_lds_window);
                    restore_prio();

                    // sync point 4
                    wg_sync_lds();

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    // Load i+2
                    load_tile_by_inline_asm(in_tmp_buffers(number<i>{}), in_copy_dram_window);
                });

                loop += NumPrefetch;
            } while(loop < num_loop - NumPrefetch);
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto i) {
                __builtin_amdgcn_sched_barrier(0);
                buffer_load_fence(in_copy_dram_window.get_num_of_access() * (NumPrefetch - 1 - i));
                __builtin_amdgcn_sched_barrier(0);

                tile_elementwise_inout(
                    in_elem_op, in_tmp_buffers(number<i>{}), in_tmp_buffers(number<i>{}));

                // Write to LDS
                promote_prio();
                store_tile(in_copy_lds_window, in_tmp_buffers[number<i>{}], bool_constant<true>{});
                restore_prio();

                // sync point 5
                wg_sync();

                // sync point 6
                wg_sync_lds();

                // Read num_loop-i-NumPrefetch
                promote_prio();
                const auto in_warp_tensors  = blockwise_gemm.LdsLoadIn(in_gemm_lds_window);
                const auto wei_warp_tensors = blockwise_gemm.LdsLoadWei(wei_gemm_lds_window);
                restore_prio();

                // sync point 7
                wg_sync_lds();

                // Mmac num_loop-i-NumPrefetch-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();
            });
        }

        return out_block_tensor;
    }

    template <typename InGemmLdsWindow,
              typename WeiCopyDramWindow,
              typename WeiCopyLdsWindow,
              typename WeiGemmLdsWindow,
              typename WeiElementwiseOp,
              bool HasHotLoop,
              index_t MWGs_                       = MWGs,
              index_t NWGs_                       = NWGs,
              typename std::enable_if<std::is_same_v<number<MWGs_>, number<1>> &&
                                          std::is_same_v<number<NWGs_>, number<2>>,
                                      bool>::type = false>
    CK_TILE_DEVICE auto operator()(const InGemmLdsWindow& in_gemm_lds_window,
                                   WeiCopyDramWindow& wei_copy_dram_window,
                                   WeiCopyLdsWindow& wei_copy_lds_window,
                                   const WeiGemmLdsWindow& wei_gemm_lds_window,
                                   const WeiElementwiseOp& wei_elem_op,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        auto out_block_tensor = blockwise_gemm.MakeOutBlockTile();

        // initialize out buffer
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);

        // sync point 1
        wg_sync();

        statically_indexed_array<decltype(load_tile_by_inline_asm(wei_copy_dram_window)),
                                 NumPrefetch>
            wei_tmp_buffers;

        // Load 0 ~ NumPrefetch -2
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(wei_tmp_buffers(number<i>{}), wei_copy_dram_window);
            advance_tile(wei_copy_dram_window);
        });

        // Load NumPrefetch - 1
        load_tile_by_inline_asm(wei_tmp_buffers(number<NumPrefetch - 1>{}), wei_copy_dram_window);

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumPrefetch, 1>{}([&](auto i) {
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(wei_copy_dram_window.get_num_of_access() * (NumPrefetch - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    tile_elementwise_inout(
                        wei_elem_op, wei_tmp_buffers(number<i>{}), wei_tmp_buffers(number<i>{}));

                    // Write to LDS
                    promote_prio();
                    store_tile(
                        wei_copy_lds_window, wei_tmp_buffers[number<i>{}], bool_constant<true>{});
                    restore_prio();

                    // sync point 2
                    wg_sync();

                    advance_tile(wei_copy_dram_window);

                    // sync point 3
                    wg_sync_lds();

                    // Read i
                    promote_prio();
                    const auto in_warp_tensors  = blockwise_gemm.LdsLoadIn(in_gemm_lds_window);
                    const auto wei_warp_tensors = blockwise_gemm.LdsLoadWei(wei_gemm_lds_window);
                    restore_prio();

                    // sync point 4
                    wg_sync_lds();

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    // Load i+2
                    load_tile_by_inline_asm(wei_tmp_buffers(number<i>{}), wei_copy_dram_window);
                });

                loop += NumPrefetch;
            } while(loop < num_loop - NumPrefetch);
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto i) {
                __builtin_amdgcn_sched_barrier(0);
                buffer_load_fence(wei_copy_dram_window.get_num_of_access() * (NumPrefetch - 1 - i));
                __builtin_amdgcn_sched_barrier(0);

                tile_elementwise_inout(
                    wei_elem_op, wei_tmp_buffers(number<i>{}), wei_tmp_buffers(number<i>{}));

                // Write to LDS
                promote_prio();
                store_tile(
                    wei_copy_lds_window, wei_tmp_buffers[number<i>{}], bool_constant<true>{});
                restore_prio();

                // sync point 5
                wg_sync();

                // sync point 6
                wg_sync_lds();

                // Read num_loop-i-NumPrefetch
                promote_prio();
                const auto in_warp_tensors  = blockwise_gemm.LdsLoadIn(in_gemm_lds_window);
                const auto wei_warp_tensors = blockwise_gemm.LdsLoadWei(wei_gemm_lds_window);
                restore_prio();

                // sync point 7
                wg_sync_lds();

                // Mmac num_loop-i-NumPrefetch-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();
            });
        }

        return out_block_tensor;
    }
};

} // namespace ck_tile
