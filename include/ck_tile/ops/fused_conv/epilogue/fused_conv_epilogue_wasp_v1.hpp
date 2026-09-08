// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common/tensor_layout.hpp"

namespace ck_tile {
template <typename Problem_, typename WarpGemm_>
struct FusedConvEpilogueWaspV1
{
    using Problem       = remove_cvref_t<Problem_>;
    using WarpGemm      = remove_cvref_t<WarpGemm_>;
    using OutWarpDstr   = remove_cvref_t<typename WarpGemm::CWarpDstr>;
    using OutWarpTensor = remove_cvref_t<typename WarpGemm::CWarpTensor>;

    using AccDataType  = remove_cvref_t<typename Problem::AccDataType>;
    using OutDataType  = remove_cvref_t<typename Problem::OutDataType>;
    using BiasDataType = remove_cvref_t<typename Problem::BiasDataType>;
    using ResDataType  = remove_cvref_t<typename Problem::ResDataType>;

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
    static constexpr index_t num_loop = SFC::get_num_of_access();

    static constexpr index_t NumPrefetch = (num_loop / 2) >= 1 ? 2 : 1;

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
    MakeLdsStoreWindow(void* p_smem, index_t smem_elem_offset, number<vec_len> = {})
    {
        // default wave schedule order
        const index_t wave_id_m = get_sub_warp_id(Problem::SubWGSize) / NWarpsPerWG;
        const index_t wave_id_n = get_sub_warp_id(Problem::SubWGSize) - wave_id_m * NWarpsPerWG;

        // TODO: how to optimize lds store?
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
    MakeLdsLoadWindow(void* p_smem, index_t smem_elem_offset, number<vec_len> = {})
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

    template <typename OutDramWindow,
              typename BiasDramWindow,
              typename AccTile,
              typename ElementwiseOp>
    CK_TILE_DEVICE void operator()(OutDramWindow& out_dram_window,
                                   BiasDramWindow& bias_dram_window_,
                                   const AccTile& acc_tile,
                                   const ElementwiseOp& elem_op,
                                   void* p_smem,
                                   index_t smem_elem_offset) const
    {
        auto lds_store_window = MakeLdsStoreWindow(p_smem, smem_elem_offset, number<1>{});
        auto lds_load_window  = MakeLdsLoadWindow(p_smem, smem_elem_offset, number<OutVecLen>{});

        auto bias_dram_window = make_tile_window(bias_dram_window_.get_bottom_tensor_view(),
                                                 bias_dram_window_.get_window_lengths(),
                                                 bias_dram_window_.get_window_origin(),
                                                 MakeDramTileDstr());

        constexpr index_t bias_load_issue = bias_dram_window.get_num_of_access();

        // bias buffer
        statically_indexed_array<decltype(load_tile(bias_dram_window)), NumPrefetch> bias_buffers;

        // prefetch bias, res
        static_for<0, NumPrefetch - 1, 1>{}([&](auto i) {
            load_tile_by_inline_asm(bias_buffers(i), bias_dram_window);

            constexpr auto step = SFC::get_forward_step(i);
            move_tile_window(
                bias_dram_window,
                {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
        });

        load_tile_by_inline_asm(bias_buffers(number<NumPrefetch - 1>{}), bias_dram_window);

        static_assert(num_loop % NumPrefetch == 0);

        constexpr auto out_warp_y_lengths =
            to_sequence(OutWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
        constexpr auto out_warp_y_index_zeros = uniform_sequence_gen_t<OutWarpDstr::NDimY, 0>{};

        // main loop
        if constexpr((num_loop / NumPrefetch) != 1)
        {
            static_for<0, num_loop - NumPrefetch, NumPrefetch>{}([&](auto outer_i) {
                static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                    constexpr auto i           = number<outer_i + inner_i>{};
                    constexpr auto idx         = SFC::get_index(number<i>{});
                    constexpr auto m_warp_iter = number<idx.at(number<0>{})>{};
                    constexpr auto n_warp_iter = number<idx.at(number<1>{})>{};

                    // store acc tile into lds
                    OutWarpTensor acc_warp_tensor;

                    acc_warp_tensor.get_thread_buffer() = acc_tile.get_y_sliced_thread_data(
                        merge_sequences(sequence<m_warp_iter, n_warp_iter>{},
                                        out_warp_y_index_zeros),
                        merge_sequences(sequence<1, 1>{}, out_warp_y_lengths));

                    // safe guard for ds write
                    wg_sync_lds(bool_constant<true>{});

                    {
                        // TODO: how to apply packed cvt?
                        const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);

                        // lds store
                        store_tile(lds_store_window, out_warp_tensor);
                    }

                    // safe guard for ds read
                    wg_sync_lds(bool_constant<true>{});

                    {
                        // lds load
                        auto out_warp_tensor =
                            load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                        // wait bias load
                        // TODO: enable ls_ooo?
                        __builtin_amdgcn_sched_barrier(0);
                        buffer_load_fence(bias_load_issue * (NumPrefetch - 1));
                        __builtin_amdgcn_sched_barrier(0);

                        // apply elementwise op
                        __builtin_amdgcn_sched_barrier(0);
                        tile_elementwise_inout(
                            elem_op, out_warp_tensor, out_warp_tensor, bias_buffers[inner_i]);
                        __builtin_amdgcn_sched_barrier(0);

                        // global store
                        store_tile(out_dram_window, out_warp_tensor);
                    }

                    // move bias window
                    {
                        constexpr auto step = SFC::get_forward_step(number<i + NumPrefetch - 1>{});
                        move_tile_window(bias_dram_window,
                                         {step.at(number<0>{}) * MPerWGPerIter,
                                          step.at(number<1>{}) * NPerWGPerIter});
                    }

                    // move out window
                    {
                        constexpr auto step = SFC::get_forward_step(i);
                        move_tile_window(out_dram_window,
                                         {step.at(number<0>{}) * MPerWGPerIter,
                                          step.at(number<1>{}) * NPerWGPerIter});
                    }

                    // issue bias prefetch
                    load_tile_by_inline_asm(bias_buffers(inner_i), bias_dram_window);
                });
            });
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                constexpr auto i           = number<num_loop - NumPrefetch + inner_i>{};
                constexpr auto idx         = SFC::get_index(i);
                constexpr auto m_warp_iter = number<idx.at(number<0>{})>{};
                constexpr auto n_warp_iter = number<idx.at(number<1>{})>{};

                // store acc tile into lds
                OutWarpTensor acc_warp_tensor;

                acc_warp_tensor.get_thread_buffer() = acc_tile.get_y_sliced_thread_data(
                    merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, out_warp_y_index_zeros),
                    merge_sequences(sequence<1, 1>{}, out_warp_y_lengths));

                // safe guard for ds write
                wg_sync_lds(bool_constant<true>{});

                {
                    // TODO: how to apply packed cvt?
                    const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);

                    // lds store
                    store_tile(lds_store_window, out_warp_tensor);
                }

                // safe guard for ds read
                wg_sync_lds(bool_constant<true>{});

                {
                    // lds load
                    auto out_warp_tensor =
                        load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                    // wait bias load
                    // TODO: enable ls_ooo?
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence(bias_load_issue * (NumPrefetch - 1 - inner_i));
                    __builtin_amdgcn_sched_barrier(0);

                    // apply elementwise op
                    __builtin_amdgcn_sched_barrier(0);
                    tile_elementwise_inout(
                        elem_op, out_warp_tensor, out_warp_tensor, bias_buffers[inner_i]);
                    __builtin_amdgcn_sched_barrier(0);

                    // global store
                    store_tile(out_dram_window, out_warp_tensor);
                }

                // move out window
                if constexpr(i < num_loop - 1)
                {
                    constexpr auto step = SFC::get_forward_step(i);
                    move_tile_window(out_dram_window,
                                     {step.at(number<0>{}) * MPerWGPerIter,
                                      step.at(number<1>{}) * NPerWGPerIter});
                }
            });
        }
    }

    template <typename OutDramWindow,
              typename BiasDramWindow,
              typename ResDramWindow,
              typename AccTile,
              typename ElementwiseOp>
    CK_TILE_DEVICE void operator()(OutDramWindow& out_dram_window,
                                   BiasDramWindow& bias_dram_window_,
                                   ResDramWindow& res_dram_window_,
                                   const AccTile& acc_tile,
                                   const ElementwiseOp& elem_op,
                                   void* p_smem,
                                   index_t smem_elem_offset) const
    {
        // out lds store/load window
        auto lds_store_window = MakeLdsStoreWindow(p_smem, smem_elem_offset, number<1>{});
        auto lds_load_window  = MakeLdsLoadWindow(p_smem, smem_elem_offset, number<OutVecLen>{});

        // bias/res dram window
        auto bias_dram_window = make_tile_window(bias_dram_window_.get_bottom_tensor_view(),
                                                 bias_dram_window_.get_window_lengths(),
                                                 bias_dram_window_.get_window_origin(),
                                                 MakeDramTileDstr());

        auto res_dram_window = make_tile_window(res_dram_window_.get_bottom_tensor_view(),
                                                res_dram_window_.get_window_lengths(),
                                                res_dram_window_.get_window_origin(),
                                                MakeDramTileDstr());

        constexpr index_t bias_load_issue = bias_dram_window.get_num_of_access();
        constexpr index_t res_load_issue  = res_dram_window.get_num_of_access();

        // bias/res buffer
        statically_indexed_array<decltype(load_tile(bias_dram_window)), NumPrefetch> bias_buffers;
        statically_indexed_array<decltype(load_tile(res_dram_window)), NumPrefetch> res_buffers;

        // prefetch bias, res
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

        constexpr auto out_warp_y_lengths =
            to_sequence(OutWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
        constexpr auto out_warp_y_index_zeros = uniform_sequence_gen_t<OutWarpDstr::NDimY, 0>{};

        // main loop
        if constexpr((num_loop / NumPrefetch) != 1)
        {
            static_for<0, num_loop - NumPrefetch, NumPrefetch>{}([&](auto outer_i) {
                static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                    constexpr auto i           = number<outer_i + inner_i>{};
                    constexpr auto idx         = SFC::get_index(number<i>{});
                    constexpr auto m_warp_iter = number<idx.at(number<0>{})>{};
                    constexpr auto n_warp_iter = number<idx.at(number<1>{})>{};

                    // store acc tile into lds
                    OutWarpTensor acc_warp_tensor;

                    acc_warp_tensor.get_thread_buffer() = acc_tile.get_y_sliced_thread_data(
                        merge_sequences(sequence<m_warp_iter, n_warp_iter>{},
                                        out_warp_y_index_zeros),
                        merge_sequences(sequence<1, 1>{}, out_warp_y_lengths));

                    // safe guard for ds write
                    wg_sync_lds(bool_constant<true>{});

                    {
                        // TODO: how to apply packed cvt?
                        const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);

                        // lds store
                        store_tile(lds_store_window, out_warp_tensor);
                    }

                    // safe guard for ds read
                    wg_sync_lds(bool_constant<true>{});

                    {
                        // lds load
                        auto out_warp_tensor =
                            load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                        // wait bias/res load
                        __builtin_amdgcn_sched_barrier(0);
                        buffer_load_fence((bias_load_issue + res_load_issue) * (NumPrefetch - 1));
                        __builtin_amdgcn_sched_barrier(0);

                        // apply elementwise op
                        __builtin_amdgcn_sched_barrier(0);
                        tile_elementwise_inout(elem_op,
                                               out_warp_tensor,
                                               out_warp_tensor,
                                               bias_buffers[inner_i],
                                               res_buffers[inner_i]);
                        __builtin_amdgcn_sched_barrier(0);

                        // global store
                        store_tile(out_dram_window, out_warp_tensor);
                    }

                    // move bias/res window
                    {
                        constexpr auto step = SFC::get_forward_step(number<i + NumPrefetch - 1>{});
                        move_tile_window(bias_dram_window,
                                         {step.at(number<0>{}) * MPerWGPerIter,
                                          step.at(number<1>{}) * NPerWGPerIter});
                        move_tile_window(res_dram_window,
                                         {step.at(number<0>{}) * MPerWGPerIter,
                                          step.at(number<1>{}) * NPerWGPerIter});
                    }

                    // move out window
                    {
                        constexpr auto step = SFC::get_forward_step(i);
                        move_tile_window(out_dram_window,
                                         {step.at(number<0>{}) * MPerWGPerIter,
                                          step.at(number<1>{}) * NPerWGPerIter});
                    }

                    // issue bias/res prefetch
                    load_tile_by_inline_asm(bias_buffers(inner_i), bias_dram_window);
                    load_tile_by_inline_asm(res_buffers(inner_i), res_dram_window);
                });
            });
        }

        // tail
        {
            static_for<0, NumPrefetch, 1>{}([&](auto inner_i) {
                constexpr auto i           = number<num_loop - NumPrefetch + inner_i>{};
                constexpr auto idx         = SFC::get_index(number<i>{});
                constexpr auto m_warp_iter = number<idx.at(number<0>{})>{};
                constexpr auto n_warp_iter = number<idx.at(number<1>{})>{};

                // store acc tile into lds
                OutWarpTensor acc_warp_tensor;

                acc_warp_tensor.get_thread_buffer() = acc_tile.get_y_sliced_thread_data(
                    merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, out_warp_y_index_zeros),
                    merge_sequences(sequence<1, 1>{}, out_warp_y_lengths));

                // safe guard for ds write
                wg_sync_lds(bool_constant<true>{});

                {
                    // TODO: how to apply packed cvt?
                    const auto out_warp_tensor = cast_tile<OutDataType>(acc_warp_tensor);

                    // lds store
                    store_tile(lds_store_window, out_warp_tensor);
                }

                // safe guard for ds read
                wg_sync_lds(bool_constant<true>{});

                {
                    // lds load
                    auto out_warp_tensor =
                        load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

                    // wait bias/res load
                    __builtin_amdgcn_sched_barrier(0);
                    buffer_load_fence((bias_load_issue + res_load_issue) *
                                      (NumPrefetch - 1 - inner_i));
                    __builtin_amdgcn_sched_barrier(0);

                    // apply elementwise op
                    __builtin_amdgcn_sched_barrier(0);
                    tile_elementwise_inout(elem_op,
                                           out_warp_tensor,
                                           out_warp_tensor,
                                           bias_buffers[inner_i],
                                           res_buffers[inner_i]);
                    __builtin_amdgcn_sched_barrier(0);

                    // global store
                    store_tile(out_dram_window, out_warp_tensor);
                }

                // move out window
                if constexpr(i < num_loop - 1)
                {
                    constexpr auto step = SFC::get_forward_step(i);
                    move_tile_window(out_dram_window,
                                     {step.at(number<0>{}) * MPerWGPerIter,
                                      step.at(number<1>{}) * NPerWGPerIter});
                }
            });
        }
    }

    template <typename OutDramWindow, typename AccTile, typename ElementwiseOp>
    CK_TILE_DEVICE void operator()(OutDramWindow& out_dram_window,
                                   const AccTile& acc_tile,
                                   const ElementwiseOp& elem_op,
                                   void* p_smem,
                                   index_t smem_elem_offset) const
    {
        auto lds_store_window = MakeLdsStoreWindow(p_smem, smem_elem_offset, number<1>{});
        auto lds_load_window  = MakeLdsLoadWindow(p_smem, smem_elem_offset, number<OutVecLen>{});

        constexpr auto out_warp_y_lengths =
            to_sequence(OutWarpDstr{}.get_ys_to_d_descriptor().get_lengths());
        constexpr auto out_warp_y_index_zeros = uniform_sequence_gen_t<OutWarpDstr::NDimY, 0>{};

        static_for<0, num_loop, 1>{}([&](auto i) {
            constexpr auto idx         = SFC::get_index(number<i>{});
            constexpr auto m_warp_iter = number<idx.at(number<0>{})>{};
            constexpr auto n_warp_iter = number<idx.at(number<1>{})>{};

            // store acc tile into lds
            OutWarpTensor acc_warp_tensor;

            acc_warp_tensor.get_thread_buffer() = acc_tile.get_y_sliced_thread_data(
                merge_sequences(sequence<m_warp_iter, n_warp_iter>{}, out_warp_y_index_zeros),
                merge_sequences(sequence<1, 1>{}, out_warp_y_lengths));

            // TODO: how to apply packed cvt?
            const auto out_warp_tensor_casted = cast_tile<OutDataType>(acc_warp_tensor);

            // lds store
            wg_sync_lds(bool_constant<true>{});
            store_tile(lds_store_window, out_warp_tensor_casted);
            wg_sync_lds(bool_constant<true>{});

            // lds load
            auto out_warp_tensor = load_tile(make_tile_window(lds_load_window, MakeDramTileDstr()));

            // apply elementwise op
            tile_elementwise_inout(elem_op, out_warp_tensor, out_warp_tensor);

            // global store
            store_tile(out_dram_window, out_warp_tensor);

            // move out window
            if constexpr(i != num_loop - 1)
            {
                constexpr auto step = SFC::get_forward_step(i);
                move_tile_window(
                    out_dram_window,
                    {step.at(number<0>{}) * MPerWGPerIter, step.at(number<1>{}) * NPerWGPerIter});
            }
        });
    }
};

} // namespace ck_tile
