// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common/tensor_layout.hpp"
#include "ck_tile/ops/fused_conv/utility/fused_conv_mode_traits.hpp"

namespace ck_tile {

template <typename Problem_, typename WarpGemm_>
struct FusedConvEpilogueWaspV2
{
    using Problem  = remove_cvref_t<Problem_>;
    using WarpGemm = remove_cvref_t<WarpGemm_>;

    using AccDataType  = remove_cvref_t<typename Problem::AccDataType>;
    using OutDataType  = remove_cvref_t<typename Problem::OutDataType>;
    using BiasDataType = remove_cvref_t<typename Problem::BiasDataType>;
    using ResDataType  = remove_cvref_t<typename Problem::ResDataType>;

    using EpilogueOp = remove_cvref_t<typename Problem::OutElementwiseOp>;
    // infer fuse mode
    static constexpr auto FuseMode = ck_tile::FusedConvModeTraits<EpilogueOp>::value;

    using AccWarpDstEncoding = typename WarpGemm::WarpGemmAttribute::CWarpPermuteDstrEncoding;
    using AccWarpDstr =
        remove_cvref_t<decltype(make_static_tile_distribution(AccWarpDstEncoding{}))>;
    using AccWarpTensor = static_distributed_tensor<AccDataType, AccWarpDstr>;

    static constexpr index_t MWarpIterPerWG  = Problem::MWarpIterPerWG;
    static constexpr index_t NWarpIterPerWG  = Problem::NWarpIterPerWG;
    static constexpr index_t MWarpsPerWG     = Problem::MWarpsPerWG;
    static constexpr index_t NWarpsPerWG     = Problem::NWarpsPerWG;
    static constexpr index_t MmmacIter       = Problem::MmmacIter;
    static constexpr index_t NmmacIter       = Problem::NmmacIter;
    static constexpr index_t MPerMmac        = Problem::MPerMmac;
    static constexpr index_t NPerMmac        = Problem::NPerMmac;
    static constexpr index_t MmmacInterleave = Problem::MmmacInterleave;
    static constexpr index_t NmmacInterleave = Problem::NmmacInterleave;

    // contigous warp tile per shuffle
    static constexpr index_t MPerWarp = MmmacIter * MPerMmac * MmmacInterleave;
    static constexpr index_t NPerWarp = NmmacIter * NPerMmac * NmmacInterleave;
    static constexpr index_t NumWarps = MWarpsPerWG * NWarpsPerWG;

    // contigous wg tile per shuffle
    static constexpr index_t MPerWGPerIter = MWarpsPerWG * MPerWarp;
    static constexpr index_t NPerWGPerIter = NWarpsPerWG * NPerWarp;

    static constexpr index_t SubWGSize = Problem::SubWGSize;
    static constexpr index_t WGSize    = Problem::WGSize;

    static constexpr index_t OutVecLen = Problem::OutGmemStoreVecLen;

    using SFC = space_filling_curve<sequence<MWarpIterPerWG, NWarpIterPerWG>,
                                    sequence<0, 1>,
                                    sequence<1, 1>>;

    // outer loop
    static constexpr index_t num_loop    = SFC::get_num_of_access();
    static constexpr index_t NumPrefetch = (num_loop / 2) >= 1 ? 2 : 1;
    static constexpr bool has_hot_loop   = (num_loop / NumPrefetch) > 1;

    static constexpr auto acc_warp_y_lengths =
        to_sequence(AccWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
    static constexpr auto acc_warp_y_index_zeros = uniform_sequence_gen_t<AccWarpDstr::NDimY, 0>{};

    CK_TILE_HOST_DEVICE static constexpr auto GetTileLengths()
    {
        return make_tuple(number<MPerWGPerIter>{}, number<NPerWGPerIter>{});
    }

    template <index_t vec_len = 1>
    CK_TILE_HOST_DEVICE static constexpr auto MakeLdsDesc(number<vec_len> = {})
    {
        return make_naive_tensor_descriptor_packed(
            make_tuple(number<MPerWGPerIter>{}, number<NPerWGPerIter>{}), number<vec_len>{});
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return MakeLdsDesc().get_element_space_size() * sizeof(OutDataType) * Problem::MWGs *
               Problem::NWGs;
    }

    template <index_t vec_len>
    CK_TILE_HOST_DEVICE static constexpr auto
    MakeLdsStoreWindow(void* p_smem, const index_t smem_elem_offset, number<vec_len> = {})
    {
        // default wave schedule order
        const index_t wave_id_m = get_sub_warp_id(Problem::SubWGSize) / NWarpsPerWG;
        const index_t wave_id_n = get_sub_warp_id(Problem::SubWGSize) - wave_id_m * NWarpsPerWG;

        constexpr auto lds_desc = MakeLdsDesc(number<vec_len>{});
        auto lds_view           = make_tensor_view<address_space_enum::lds>(
            static_cast<OutDataType*>(p_smem) + smem_elem_offset, lds_desc);

        auto lds_window =
            make_tile_window(lds_view,
                             make_tuple(number<MPerWarp>{}, number<NPerWarp>{}),
                             {number<MPerWarp>{} * wave_id_m, number<NPerWarp>{} * wave_id_n});

        return lds_window;
    }

    template <index_t vec_len>
    CK_TILE_HOST_DEVICE static constexpr auto
    MakeLdsLoadWindow(void* p_smem, const index_t smem_elem_offset, number<vec_len> = {})
    {
        constexpr auto lds_desc = MakeLdsDesc(number<vec_len>{});
        auto lds_view           = make_tensor_view<address_space_enum::lds>(
            static_cast<OutDataType*>(p_smem) + smem_elem_offset, lds_desc);

        auto lds_window = make_tile_window(
            lds_view, make_tuple(number<MPerWGPerIter>{}, number<NPerWGPerIter>{}), {0, 0});

        return lds_window;
    }

    CK_TILE_HOST_DEVICE static constexpr auto MakeDramTileDstr()
    {
        constexpr index_t ElemsTransPerLane = MPerWGPerIter * NPerWGPerIter / WGSize;
        constexpr index_t NLaneSlice        = OutVecLen;
        constexpr index_t MLaneSlice        = ElemsTransPerLane / NLaneSlice;

        constexpr index_t NLaneCluster = NPerWGPerIter / NLaneSlice;

        if constexpr(get_warp_size() % NLaneCluster == 0)
        {
            constexpr index_t MLaneCluster = get_warp_size() / NLaneCluster;

            static_assert(MLaneCluster * NumWarps <= MPerWGPerIter);

            return make_static_tile_distribution(
                tile_distribution_encoding<sequence<1>,
                                           tuple<sequence<MLaneSlice, NumWarps, MLaneCluster>,
                                                 sequence<NLaneCluster, NLaneSlice>>,
                                           tuple<sequence<1>, sequence<1, 2>>,
                                           tuple<sequence<1>, sequence<2, 0>>,
                                           sequence<1, 2>,
                                           sequence<0, 1>>{},
                bool_constant<true>{},
                number<SubWGSize>{});
        }
        else
        {
            static_assert(false, "Not implemented yet");
        }
    }

    template <typename AccBlockTensor,
              typename OutDramWindow,
              typename LdsStoreWindow,
              typename LdsLoadWindow,
              index_t rank>
    CK_TILE_DEVICE void RunUnaryEpilogue(const AccBlockTensor& acc_block_tensor,
                                         OutDramWindow& out_dram_window,
                                         LdsStoreWindow& lds_store_window,
                                         LdsLoadWindow& lds_load_window,
                                         number<rank>) const
    {
        // ebarrier for warpgroup sync
        hcu_ebarrier ebar{rank, SubWGSize};

        // epilogue loop fn
        const auto epilogue_loop_fn = [&](auto i) {
            constexpr auto idx         = SFC::get_index(number<i>{});
            constexpr auto m_warp_iter = number<idx.at(number<0>{})>{};
            constexpr auto n_warp_iter = number<idx.at(number<1>{})>{};

            // store acc tensor into lds
            AccWarpTensor acc_warp_tensor;
            acc_warp_tensor.get_thread_buffer() = acc_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, acc_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_y_lengths));

            // safe guard ds write
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            ebar.sync();
            __builtin_amdgcn_sched_barrier(0);

            {
                const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);
                // issue ds write
                store_tile(lds_store_window, out_warp_tensor);
            }

            // safe gurad for ds read
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            ebar.sync();
            __builtin_amdgcn_sched_barrier(0);

            {
                // issue ds read
                auto out_warp_tensor =
                    load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                // apply elementwise op
                __builtin_amdgcn_sched_barrier(0);
                tile_elementwise_inout(EpilogueOp{}, out_warp_tensor, out_warp_tensor);
                __builtin_amdgcn_sched_barrier(0);

                // issue buffer store
                store_tile(out_dram_window, out_warp_tensor);
            }

            // move out window
            if constexpr(i != num_loop - 1)
            {
                constexpr auto step = SFC::get_forward_step(i);
                move_tile_window(
                    out_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
            }
        };

        static_for<0, num_loop, 1>{}([&](auto i) { epilogue_loop_fn(i); });
    }

    template <typename AccBlockTensor,
              typename OutDramWindow,
              typename BiasDramWindow,
              typename LdsStoreWindow,
              typename LdsLoadWindow,
              index_t rank>
    CK_TILE_DEVICE void RunBinaryEpilogue(const AccBlockTensor& acc_block_tensor,
                                          OutDramWindow& out_dram_window,
                                          BiasDramWindow& bias_dram_window,
                                          LdsStoreWindow& lds_store_window,
                                          LdsLoadWindow& lds_load_window,
                                          number<rank>) const
    {
        // ebarrier for warpgroup sync
        hcu_ebarrier ebar{rank, SubWGSize};

        constexpr uint32_t bias_load_issue = BiasDramWindow::get_num_of_access();

        // bias buffer
        statically_indexed_array<decltype(load_tile(bias_dram_window)), NumPrefetch> bias_buffers;

        // prefetch bias
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(bias_buffers(i), bias_dram_window);

            constexpr auto step = SFC::get_forward_step(i);
            move_tile_window(
                bias_dram_window,
                {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
        });

        load_tile_by_inline_asm(bias_buffers(number<NumPrefetch - 1>{}), bias_dram_window);

        static_assert(num_loop % NumPrefetch == 0);

        const auto epilogue_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto inner_i      = number<i % NumPrefetch>{};
            constexpr auto idx          = SFC::get_index(number<i>{});
            constexpr auto m_warp_iter  = number<idx.at(number<0>{})>{};
            constexpr auto n_warp_iter  = number<idx.at(number<1>{})>{};
            constexpr auto is_last_loop = is_tail_loop && (inner_i == NumPrefetch - 1);

            // store acc tensor into lds
            AccWarpTensor acc_warp_tensor;

            acc_warp_tensor.get_thread_buffer() = acc_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, acc_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_y_lengths));

            // safe gurad for ds write
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            ebar.sync();
            __builtin_amdgcn_sched_barrier(0);

            {
                const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);

                // issue ds write
                store_tile(lds_store_window, out_warp_tensor);
            }

            // safe gurad for ds read
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            ebar.sync();
            __builtin_amdgcn_sched_barrier(0);

            {
                // issue ds read
                auto out_warp_tensor =
                    load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                // wait bias load
                constexpr uint32_t waitcnt = is_tail_loop
                                                 ? bias_load_issue * (NumPrefetch - 1 - inner_i)
                                                 : bias_load_issue * (NumPrefetch - 1);

                __builtin_amdgcn_sched_barrier(0);
                buffer_load_fence(waitcnt);
                __builtin_amdgcn_sched_barrier(0);

                // apply elementwise op
                __builtin_amdgcn_sched_barrier(0);
                tile_elementwise_inout(
                    EpilogueOp{}, out_warp_tensor, out_warp_tensor, bias_buffers[inner_i]);
                __builtin_amdgcn_sched_barrier(0);

                // issue buffer store
                store_tile(out_dram_window, out_warp_tensor);
            }

            if constexpr(!is_last_loop)
            {
                // move out window
                constexpr auto step = SFC::get_forward_step(i);
                move_tile_window(
                    out_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
            }

            if constexpr(!is_tail_loop)
            {
                // move bias window
                constexpr auto step = SFC::get_forward_step(number<i + NumPrefetch - 1>{});
                move_tile_window(
                    bias_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});

                // issue bias prefetch
                load_tile_by_inline_asm(bias_buffers(inner_i), bias_dram_window);
            }
        };

        // main loop
        if constexpr(has_hot_loop)
        {
            static_for<0, num_loop - NumPrefetch, NumPrefetch>{}([&](auto outer_i) {
                static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                    constexpr auto i = number<outer_i + inner_i>{};
                    epilogue_loop_fn(i, bool_constant<false>{});
                });
            });
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                constexpr auto i = number<num_loop - NumPrefetch + inner_i>{};
                epilogue_loop_fn(i, bool_constant<true>{});
            });
        }
    }

    template <typename AccBlockTensor,
              typename OutDramWindow,
              typename BiasDramWindow,
              typename ResDramWindow,
              typename LdsStoreWindow,
              typename LdsLoadWindow,
              index_t rank>
    CK_TILE_DEVICE void RunTenaryEpilogue(const AccBlockTensor& acc_block_tensor,
                                          OutDramWindow& out_dram_window,
                                          BiasDramWindow& bias_dram_window,
                                          ResDramWindow& res_dram_window,
                                          LdsStoreWindow& lds_store_window,
                                          LdsLoadWindow& lds_load_window,
                                          number<rank>) const
    {
        // ebarrier for warpgroup sync
        hcu_ebarrier ebar{rank, SubWGSize};

        constexpr uint32_t bias_load_issue = BiasDramWindow::get_num_of_access();
        constexpr uint32_t res_load_issue  = ResDramWindow::get_num_of_access();

        // bias/res buffer
        statically_indexed_array<decltype(load_tile(bias_dram_window)), NumPrefetch> bias_buffers;
        statically_indexed_array<decltype(load_tile(res_dram_window)), NumPrefetch> res_buffers;

        // prefetch bias/res
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(bias_buffers(i), bias_dram_window);
            load_tile_by_inline_asm(res_buffers(i), res_dram_window);

            constexpr auto step = SFC::get_forward_step(i);
            move_tile_window(
                bias_dram_window,
                {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
            move_tile_window(
                res_dram_window,
                {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
        });

        load_tile_by_inline_asm(bias_buffers(number<NumPrefetch - 1>{}), bias_dram_window);
        load_tile_by_inline_asm(res_buffers(number<NumPrefetch - 1>{}), res_dram_window);

        static_assert(num_loop % NumPrefetch == 0);

        const auto epilogue_loop_fn = [&](auto i, auto is_tail_loop) {
            constexpr auto inner_i      = number<i % NumPrefetch>{};
            constexpr auto idx          = SFC::get_index(number<i>{});
            constexpr auto m_warp_iter  = number<idx.at(number<0>{})>{};
            constexpr auto n_warp_iter  = number<idx.at(number<1>{})>{};
            constexpr auto is_last_loop = is_tail_loop && (inner_i == NumPrefetch - 1);

            // store acc tensor into lds
            AccWarpTensor acc_warp_tensor;

            acc_warp_tensor.get_thread_buffer() = acc_block_tensor.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, acc_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, acc_warp_y_lengths));

            // safe gurad for ds write
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            ebar.sync();
            __builtin_amdgcn_sched_barrier(0);

            {
                const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);

                // issue ds write
                store_tile(lds_store_window, out_warp_tensor);
            }

            // safe gurad for ds read
            __builtin_amdgcn_sched_barrier(0);
            lds_fence();
            ebar.sync();
            __builtin_amdgcn_sched_barrier(0);

            {
                // issue ds read
                auto out_warp_tensor =
                    load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                // wait bias load
                constexpr uint32_t waitcnt =
                    is_tail_loop ? (bias_load_issue + res_load_issue) * (NumPrefetch - 1 - inner_i)
                                 : (bias_load_issue + res_load_issue) * (NumPrefetch - 1);

                __builtin_amdgcn_sched_barrier(0);
                buffer_load_fence(waitcnt);
                __builtin_amdgcn_sched_barrier(0);

                // apply elementwise op
                __builtin_amdgcn_sched_barrier(0);
                tile_elementwise_inout(EpilogueOp{},
                                       out_warp_tensor,
                                       out_warp_tensor,
                                       bias_buffers[inner_i],
                                       res_buffers[inner_i]);
                __builtin_amdgcn_sched_barrier(0);

                // issue buffer store
                store_tile(out_dram_window, out_warp_tensor);
            }

            if constexpr(!is_last_loop)
            {
                // move out window
                constexpr auto step = SFC::get_forward_step(i);
                move_tile_window(
                    out_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
            }

            if constexpr(!is_tail_loop)
            {
                // move bias/res window
                constexpr auto step = SFC::get_forward_step(number<i + NumPrefetch - 1>{});
                move_tile_window(
                    bias_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
                move_tile_window(
                    res_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});

                // issue bias/res prefetch
                load_tile_by_inline_asm(bias_buffers(inner_i), bias_dram_window);
                load_tile_by_inline_asm(res_buffers(inner_i), res_dram_window);
            }
        };

        // main loop
        if constexpr(has_hot_loop)
        {
            static_for<0, num_loop - NumPrefetch, NumPrefetch>{}([&](auto outer_i) {
                static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                    constexpr auto i = number<outer_i + inner_i>{};
                    epilogue_loop_fn(i, bool_constant<false>{});
                });
            });
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                constexpr auto i = number<num_loop - NumPrefetch + inner_i>{};
                epilogue_loop_fn(i, bool_constant<true>{});
            });
        }
    }

    template <typename AccBlockTensor,
              typename OutDramWindow,
              typename BiasDramWindow,
              typename ResDramWindow,
              index_t rank>
    CK_TILE_DEVICE void operator()(void* p_smem,
                                   const AccBlockTensor& acc_block_tensor,
                                   OutDramWindow& out_dram_window,
                                   BiasDramWindow& bias_dram_window_,
                                   ResDramWindow& res_dram_window_,
                                   number<rank>) const
    {
        // lds workspace offset by rank
        constexpr index_t smem_elem_offset = rank * MakeLdsDesc().get_element_space_size();

        // out lds store/load window
        auto lds_store_window =
            MakeLdsStoreWindow(p_smem, smem_elem_offset, number<NmmacInterleave>{});
        auto lds_load_window = MakeLdsLoadWindow(p_smem, smem_elem_offset, number<OutVecLen>{});

        // bias/res dram window
        auto bias_dram_window = make_tile_window(bias_dram_window_.get_bottom_tensor_view(),
                                                 bias_dram_window_.get_window_lengths(),
                                                 bias_dram_window_.get_window_origin(),
                                                 MakeDramTileDstr());

        auto res_dram_window = make_tile_window(res_dram_window_.get_bottom_tensor_view(),
                                                res_dram_window_.get_window_lengths(),
                                                res_dram_window_.get_window_origin(),
                                                MakeDramTileDstr());

        if constexpr(FuseMode == FusedConvMode::Conv || FuseMode == FusedConvMode::ConvRelu)
        {
            detail::swallow{bias_dram_window, res_dram_window};

            RunUnaryEpilogue(acc_block_tensor,
                             out_dram_window,
                             lds_store_window,
                             lds_load_window,
                             number<rank>{});
        }
        else if constexpr(FuseMode == FusedConvMode::ConvBias)
        {
            detail::swallow{res_dram_window};

            RunBinaryEpilogue(acc_block_tensor,
                              out_dram_window,
                              bias_dram_window,
                              lds_store_window,
                              lds_load_window,
                              number<rank>{});
        }
        else if constexpr(FuseMode == FusedConvMode::ConvBiasRelu)
        {
            detail::swallow{res_dram_window};

            RunBinaryEpilogue(acc_block_tensor,
                              out_dram_window,
                              bias_dram_window,
                              lds_store_window,
                              lds_load_window,
                              number<rank>{});
        }
        else if constexpr(FuseMode == FusedConvMode::ConvBiasResRelu)
        {
            RunTenaryEpilogue(acc_block_tensor,
                              out_dram_window,
                              bias_dram_window,
                              res_dram_window,
                              lds_store_window,
                              lds_load_window,
                              number<rank>{});
        }
    }

    // for producer, only sync with consumer WGs
    // devices with ebarrier support do not need this
    CK_TILE_DEVICE void operator()() const
    {
        static_for<0, num_loop, 1>{}([&](auto i) {
            detail::swallow{i};

            wg_sync(bool_constant<true>{});

            wg_sync(bool_constant<true>{});
        });
    }
};

} // namespace ck_tile
