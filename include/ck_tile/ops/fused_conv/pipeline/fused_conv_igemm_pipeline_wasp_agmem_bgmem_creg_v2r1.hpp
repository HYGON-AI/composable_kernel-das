// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"

namespace ck_tile {

template <typename Problem_, typename Policy_>
struct FusedConvIgemmPipelineWaspAgmemBgmemCregV2R1
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

    static constexpr index_t NumLdsStages = Problem::NumPrefetch;

    static constexpr index_t InVecLen  = Problem::InGmemLoadVecLen;
    static constexpr index_t WeiVecLen = Problem::WeiGmemLoadVecLen;
    static constexpr index_t OutVecLen = Problem::OutGmemStoreVecLen;

    static constexpr index_t MWGs = Problem::MWGs;
    static constexpr index_t NWGs = Problem::NWGs;

    static constexpr index_t PingPongDepth = 2;

    CK_TILE_HOST_DEVICE static constexpr bool IsSupported(index_t num_loop)
    {
        // TODO: improve applicability for multi-stage pipeline
        return num_loop % NumLdsStages == 0;
    }

    CK_TILE_HOST_DEVICE static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return (num_loop / NumLdsStages) > 1;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return NumLdsStages * (Policy::template GetInLdsByteSize<Problem>() +
                               Policy::template GetWeiLdsByteSize<Problem>());
    }

    // limitation
    static_assert(NumLdsStages % PingPongDepth == 0);

    // pipelines for (MWGs, NWGs) = (2, 1)
    template <typename InCopyDramWindow,
              typename WeiCopyDramWindow,
              typename InGemmLdsWindows,
              typename WeiGemmLdsWindows,
              typename InElementwiseOp,
              typename WeiElementwiseOp,
              bool HasHotLoop,
              index_t MWGs_                       = MWGs,
              index_t NWGs_                       = NWGs,
              typename std::enable_if<std::is_same_v<number<MWGs_>, number<2>> &&
                                          std::is_same_v<number<NWGs_>, number<1>>,
                                      bool>::type = false>
    CK_TILE_DEVICE auto operator()(InCopyDramWindow& in_copy_dram_window,
                                   InGemmLdsWindows& in_gemm_lds_windows,
                                   const InElementwiseOp&,
                                   WeiCopyDramWindow& wei_copy_dram_window,
                                   WeiGemmLdsWindows& wei_gemm_lds_windows,
                                   const WeiElementwiseOp&,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        // A warp windows for lds -> vgpr load
        auto in_warp_windows_arr = generate_tuple(
            [&](auto i) { return blockwise_gemm.GetAWarpWindows(in_gemm_lds_windows(i)); },
            number<NumLdsStages>{});

        // B warp windows for lds -> vgpr load
        auto wei_warp_windows_arr = generate_tuple(
            [&](auto i) { return blockwise_gemm.GetBWarpWindows(wei_gemm_lds_windows(i)); },
            number<NumLdsStages>{});

        auto out_block_tensor = blockwise_gemm.MakeCBlockTile();

        // Load 0 ~ NumLdsStages - 2
        static_for<0, NumLdsStages - 1, 1>{}([&](auto i) {
            async_load_tile_wrapped_asm(in_gemm_lds_windows(i).get_buffer_ptr(),
                                        in_copy_dram_window);
            async_load_tile_wrapped_asm(wei_gemm_lds_windows(i).get_buffer_ptr(),
                                        wei_copy_dram_window);

            advance_tile_window(in_copy_dram_window);
            advance_tile_window(wei_copy_dram_window);
        });

        // Load NumLdsStages - 1
        async_load_tile_wrapped_asm(
            in_gemm_lds_windows(number<NumLdsStages - 1>{}).get_buffer_ptr(), in_copy_dram_window);
        async_load_tile_wrapped_asm(
            wei_gemm_lds_windows(number<NumLdsStages - 1>{}).get_buffer_ptr(),
            wei_copy_dram_window);

        // initialize out buffer
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // wait first
        __builtin_amdgcn_sched_barrier(0);
        buffer_load_fence(
            (in_copy_dram_window.get_num_of_access() + wei_copy_dram_window.get_num_of_access()) *
            (NumLdsStages - 1));
        __builtin_amdgcn_sched_barrier(0);

        // sync point 1
        wg_sync();

        // read first
        promote_prio();
        auto in_warp_tensors  = load_tiles_asm(in_warp_windows_arr(number<0>{}));
        auto wei_warp_tensors = load_tiles_asm(wei_warp_windows_arr(number<0>{}));
        restore_prio();

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumLdsStages, 1>{}([&](auto i) {
                    advance_tile_window(in_copy_dram_window);
                    advance_tile_window(wei_copy_dram_window);

                    // sync point 1
                    wg_sync_lds(bool_constant<true>{});

                    // issue A global->lds i+2
                    async_load_tile_wrapped_asm(in_gemm_lds_windows(i).get_buffer_ptr(),
                                                in_copy_dram_window);

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    // sync point 2
                    wg_sync();

                    // issue B global->lds i+2
                    async_load_tile_wrapped_asm(wei_gemm_lds_windows(i).get_buffer_ptr(),
                                                wei_copy_dram_window);

                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence((in_copy_dram_window.get_num_of_access() +
                                       wei_copy_dram_window.get_num_of_access()) *
                                      (NumLdsStages - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    // sync point 3
                    wg_sync();

                    // lds prefetch
                    promote_prio();
                    in_warp_tensors =
                        load_tiles_asm(in_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    wei_warp_tensors =
                        load_tiles_asm(wei_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    restore_prio();
                });

                loop += NumLdsStages;
            } while(loop < num_loop - NumLdsStages);
        }

        // tail
        {
            static_for<0, NumLdsStages, 1>{}([&](auto i) {
                // sync point 1
                wg_sync_lds(bool_constant<true>{});

                // Mmac num_loop-i-NumLdsStages-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();

                if constexpr(i != NumLdsStages - 1)
                {
                    __builtin_amdgcn_sched_barrier(0);
                    if constexpr(NumLdsStages >= 3)
                    {
                        buffer_load_fence((in_copy_dram_window.get_num_of_access() +
                                           wei_copy_dram_window.get_num_of_access()) *
                                          (NumLdsStages - 2 - i));
                    }
                    else
                    {
                        buffer_load_fence(0);
                    }
                    __builtin_amdgcn_sched_barrier(0);
                }

                // sync point 2
                __builtin_amdgcn_sched_barrier(0);
                wg_sync();
                __builtin_amdgcn_sched_barrier(0);

                if constexpr(i != NumLdsStages - 1)
                {
                    // lds prefetch
                    promote_prio();
                    in_warp_tensors =
                        load_tiles_asm(in_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    wei_warp_tensors =
                        load_tiles_asm(wei_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    restore_prio();
                }
            });
        }

        return out_block_tensor;
    }

    template <typename InWarpDramWindows,
              typename WeiGemmLdsWindows,
              typename InElementwiseOp,
              bool HasHotLoop,
              index_t MWGs_                       = MWGs,
              index_t NWGs_                       = NWGs,
              typename std::enable_if<std::is_same_v<number<MWGs_>, number<2>> &&
                                          std::is_same_v<number<NWGs_>, number<1>>,
                                      bool>::type = false>
    CK_TILE_DEVICE auto operator()(InWarpDramWindows& in_warp_dram_windows,
                                   const InElementwiseOp&,
                                   WeiGemmLdsWindows& wei_gemm_lds_windows,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        // ping-pong buffer for A global -> vgpr load
        statically_indexed_array<decltype(load_tiles_asm(in_warp_dram_windows)), PingPongDepth>
            in_warp_tensors_arr;

        // B warp windows for lds -> vgpr load
        auto wei_warp_windows_arr = generate_tuple(
            [&](auto i) { return blockwise_gemm.GetBWarpWindows(wei_gemm_lds_windows(i)); },
            number<NumLdsStages>{});

        auto out_block_tensor = blockwise_gemm.MakeCBlockTile();

        // issue initial A global->vgpr
        in_warp_tensors_arr(number<0>{}) = load_tiles_asm(in_warp_dram_windows);

        // initialize out buffer
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);

        // sync point 1
        wg_sync();

        auto in_warp_tensors = in_warp_tensors_arr(number<0>{});

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumLdsStages, 1>{}([&](auto i) {
                    advance_tile_windows(in_warp_dram_windows);

                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // prefetch A
                    in_warp_tensors_arr(number<(i + 1) % PingPongDepth>{}) =
                        load_tiles_asm(in_warp_dram_windows);

                    // sync point 1
                    wg_sync();

                    // Read i
                    promote_prio();
                    auto wei_warp_tensors = load_tiles_asm(wei_warp_windows_arr(i));
                    restore_prio();

                    // sync point 2
                    wg_sync_lds(bool_constant<true>{});

                    // sync point 3
                    wg_sync();

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    in_warp_tensors = in_warp_tensors_arr(number<(i + 1) % PingPongDepth>{});
                });

                loop += NumLdsStages;
            } while(loop < num_loop - NumLdsStages);
        }

        // tail
        {
            static_for<0, NumLdsStages, 1>{}([&](auto i) {
                if constexpr(i != NumLdsStages - 1)
                {
                    advance_tile_windows(in_warp_dram_windows);

                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // prefetch A
                    in_warp_tensors_arr(number<(i + 1) % PingPongDepth>{}) =
                        load_tiles_asm(in_warp_dram_windows);
                }
                else
                {
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(0);
                    __builtin_amdgcn_sched_barrier(0);
                }

                // sync point 1
                wg_sync();

                // Read num_loop-i-NumLdsStages
                promote_prio();
                auto wei_warp_tensors = load_tiles_asm(wei_warp_windows_arr(i));
                restore_prio();

                // sync point 2
                wg_sync_lds(bool_constant<true>{});

                // Mmac num_loop-i-NumLdsStages-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();

                if constexpr(i != NumLdsStages - 1)
                {
                    in_warp_tensors = in_warp_tensors_arr(number<(i + 1) % PingPongDepth>{});
                }
            });
        }

        return out_block_tensor;
    }

    // pipelines for (MWGs, NWGs) = (1, 2)
    template <typename InCopyDramWindow,
              typename WeiCopyDramWindow,
              typename InGemmLdsWindows,
              typename WeiGemmLdsWindows,
              typename InElementwiseOp,
              typename WeiElementwiseOp,
              bool HasHotLoop,
              index_t MWGs_                       = MWGs,
              index_t NWGs_                       = NWGs,
              typename std::enable_if<std::is_same_v<number<MWGs_>, number<1>> &&
                                          std::is_same_v<number<NWGs_>, number<2>>,
                                      bool>::type = false>
    CK_TILE_DEVICE auto operator()(InCopyDramWindow& in_copy_dram_window,
                                   InGemmLdsWindows& in_gemm_lds_windows,
                                   const InElementwiseOp&,
                                   WeiCopyDramWindow& wei_copy_dram_window,
                                   WeiGemmLdsWindows& wei_gemm_lds_windows,
                                   const WeiElementwiseOp&,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        // A warp windows for lds -> vgpr load
        auto in_warp_windows_arr = generate_tuple(
            [&](auto i) { return blockwise_gemm.GetAWarpWindows(in_gemm_lds_windows(i)); },
            number<NumLdsStages>{});

        // B warp windows for lds -> vgpr load
        auto wei_warp_windows_arr = generate_tuple(
            [&](auto i) { return blockwise_gemm.GetBWarpWindows(wei_gemm_lds_windows(i)); },
            number<NumLdsStages>{});

        auto out_block_tensor = blockwise_gemm.MakeCBlockTile();

        // Load 0 ~ NumLdsStages - 2
        static_for<0, NumLdsStages - 1, 1>{}([&](auto i) {
            async_load_tile_wrapped_asm(in_gemm_lds_windows(i).get_buffer_ptr(),
                                        in_copy_dram_window);
            async_load_tile_wrapped_asm(wei_gemm_lds_windows(i).get_buffer_ptr(),
                                        wei_copy_dram_window);

            advance_tile_window(in_copy_dram_window);
            advance_tile_window(wei_copy_dram_window);
        });

        // Load NumLdsStages - 1
        async_load_tile_wrapped_asm(
            in_gemm_lds_windows(number<NumLdsStages - 1>{}).get_buffer_ptr(), in_copy_dram_window);
        async_load_tile_wrapped_asm(
            wei_gemm_lds_windows(number<NumLdsStages - 1>{}).get_buffer_ptr(),
            wei_copy_dram_window);

        // initialize out buffer
        __builtin_amdgcn_sched_barrier(0);
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);
        __builtin_amdgcn_sched_barrier(0);

        // wait first
        __builtin_amdgcn_sched_barrier(0);
        buffer_load_fence(
            (in_copy_dram_window.get_num_of_access() + wei_copy_dram_window.get_num_of_access()) *
            (NumLdsStages - 1));
        __builtin_amdgcn_sched_barrier(0);

        // sync point 1
        wg_sync();

        // read first
        promote_prio();
        auto in_warp_tensors  = load_tiles_asm(in_warp_windows_arr(number<0>{}));
        auto wei_warp_tensors = load_tiles_asm(wei_warp_windows_arr(number<0>{}));
        restore_prio();

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumLdsStages, 1>{}([&](auto i) {
                    advance_tile_window(in_copy_dram_window);
                    advance_tile_window(wei_copy_dram_window);

                    // sync point 1
                    wg_sync_lds(bool_constant<true>{});

                    // issue B global->lds i+2
                    async_load_tile_wrapped_asm(wei_gemm_lds_windows(i).get_buffer_ptr(),
                                                wei_copy_dram_window);

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    // sync point 2
                    wg_sync();

                    // issue A global->lds i+2
                    async_load_tile_wrapped_asm(in_gemm_lds_windows(i).get_buffer_ptr(),
                                                in_copy_dram_window);

                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence((in_copy_dram_window.get_num_of_access() +
                                       wei_copy_dram_window.get_num_of_access()) *
                                      (NumLdsStages - 1));
                    __builtin_amdgcn_sched_barrier(0);

                    // sync point 3
                    wg_sync();

                    // lds prefetch
                    promote_prio();
                    in_warp_tensors =
                        load_tiles_asm(in_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    wei_warp_tensors =
                        load_tiles_asm(wei_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    restore_prio();
                });

                loop += NumLdsStages;
            } while(loop < num_loop - NumLdsStages);
        }

        // tail
        {
            static_for<0, NumLdsStages, 1>{}([&](auto i) {
                // sync point 1
                wg_sync_lds(bool_constant<true>{});

                // Mmac num_loop-i-NumLdsStages-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();

                if constexpr(i != NumLdsStages - 1)
                {
                    __builtin_amdgcn_sched_barrier(0);
                    if constexpr(NumLdsStages >= 3)
                    {
                        buffer_load_fence((in_copy_dram_window.get_num_of_access() +
                                           wei_copy_dram_window.get_num_of_access()) *
                                          (NumLdsStages - 2 - i));
                    }
                    else
                    {
                        buffer_load_fence(0);
                    }
                    __builtin_amdgcn_sched_barrier(0);
                }

                // sync point 2
                __builtin_amdgcn_sched_barrier(0);
                wg_sync();
                __builtin_amdgcn_sched_barrier(0);

                if constexpr(i != NumLdsStages - 1)
                {
                    // lds prefetch
                    promote_prio();
                    in_warp_tensors =
                        load_tiles_asm(in_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    wei_warp_tensors =
                        load_tiles_asm(wei_warp_windows_arr(number<(i + 1) % NumLdsStages>{}));
                    restore_prio();
                }
            });
        }

        return out_block_tensor;
    }

    template <typename InGemmLdsWindows,
              typename WeiWarpDramWindows,
              typename WeiElementwiseOp,
              bool HasHotLoop,
              index_t MWGs_                       = MWGs,
              index_t NWGs_                       = NWGs,
              typename std::enable_if<std::is_same_v<number<MWGs_>, number<1>> &&
                                          std::is_same_v<number<NWGs_>, number<2>>,
                                      bool>::type = false>
    CK_TILE_DEVICE auto operator()(InGemmLdsWindows& in_gemm_lds_windows,
                                   WeiWarpDramWindows& wei_warp_dram_windows,
                                   const WeiElementwiseOp&,
                                   index_t num_loop,
                                   bool_constant<HasHotLoop>) const
    {
        constexpr auto blockwise_gemm = Policy::template GetBlockwiseGemm<Problem>();

        // A warp windows for lds -> vgpr load
        auto in_warp_windows_arr = generate_tuple(
            [&](auto i) { return blockwise_gemm.GetAWarpWindows(in_gemm_lds_windows(i)); },
            number<NumLdsStages>{});

        // ping-pong buffer for B global -> vgpr load
        statically_indexed_array<decltype(load_tiles_asm(wei_warp_dram_windows)), PingPongDepth>
            wei_warp_tensors_arr;

        auto out_block_tensor = blockwise_gemm.MakeCBlockTile();

        // issue initial B global->vgpr
        wei_warp_tensors_arr(number<0>{}) = load_tiles_asm(wei_warp_dram_windows);

        // initialize out buffer
        tile_elementwise_inout([](auto& o) { o = 0; }, out_block_tensor);

        // sync point 1
        wg_sync();

        auto wei_warp_tensors = wei_warp_tensors_arr(number<0>{});

        // main body
        if constexpr(HasHotLoop)
        {
            index_t loop = 0;
            do
            {
                //  pipeline
                static_for<0, NumLdsStages, 1>{}([&](auto i) {
                    advance_tile_windows(wei_warp_dram_windows);

                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // prefetch B
                    wei_warp_tensors_arr(number<(i + 1) % PingPongDepth>{}) =
                        load_tiles_asm(wei_warp_dram_windows);

                    // sync point 1
                    wg_sync();

                    // A lds -> vgpr load
                    promote_prio();
                    auto in_warp_tensors = load_tiles_asm(in_warp_windows_arr(i));
                    restore_prio();

                    // sync point 2
                    wg_sync_lds(bool_constant<true>{});

                    // sync point 3
                    wg_sync();

                    // Mmac i
                    promote_prio();
                    blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                    restore_prio();

                    wei_warp_tensors = wei_warp_tensors_arr(number<(i + 1) % PingPongDepth>{});
                });

                loop += NumLdsStages;
            } while(loop < num_loop - NumLdsStages);
        }

        // tail
        {
            static_for<0, NumLdsStages, 1>{}([&](auto i) {
                if constexpr(i != NumLdsStages - 1)
                {
                    advance_tile_windows(wei_warp_dram_windows);

                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(0);
                    __builtin_amdgcn_sched_barrier(0);

                    // prefetch B
                    wei_warp_tensors_arr(number<(i + 1) % PingPongDepth>{}) =
                        load_tiles_asm(wei_warp_dram_windows);
                }
                else
                {
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(0);
                    __builtin_amdgcn_sched_barrier(0);
                }

                // sync point 1
                wg_sync();

                // A lds -> vgpr load
                promote_prio();
                auto in_warp_tensors = load_tiles_asm(in_warp_windows_arr(i));
                restore_prio();

                // sync point 2
                wg_sync_lds(bool_constant<true>{});

                // Mmac num_loop-i-NumLdsStages-2
                promote_prio();
                blockwise_gemm(out_block_tensor, in_warp_tensors, wei_warp_tensors);
                restore_prio();

                if constexpr(i != NumLdsStages - 1)
                {
                    wei_warp_tensors = wei_warp_tensors_arr(number<(i + 1) % PingPongDepth>{});
                }
            });
        }

        return out_block_tensor;
    }
};

} // namespace ck_tile
