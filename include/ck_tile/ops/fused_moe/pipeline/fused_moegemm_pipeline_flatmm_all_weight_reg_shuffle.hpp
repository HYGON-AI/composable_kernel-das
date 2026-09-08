// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common/tensor_layout.hpp"
#include "ck_tile/ops/fused_moe/pipeline/fused_moegemm_pipeline_flatmm_all_weight_reg_policy.hpp"

namespace ck_tile {

/*
This pipeline deal with a gemm(actually 2 gemm) with one very small(token), one very big(weight)
we need to design the pipeline such that all waves along gemm-N dim (gemm-m only 1 wave)

    <----- gemm-N ------>
    +----+----+----+----+
    | w0 | w1 | w2 | w3 | gemm-m
    +----+----+----+----+
*/
template <typename Problem_, typename Policy_ = FusedMoeGemmPipelineFlatmmWRegPolicy>
struct FusedMoeGemmPipeline_Flatmm_Wreg_shuffle
{
    using Problem = remove_cvref_t<Problem_>;
    using Policy  = remove_cvref_t<Policy_>;

    using BlockShape = typename Problem::BlockShape; // this is FusedMoeGemmShape

    using ADataType            = typename Problem::ADataType;
    using GDataType            = typename Problem::GDataType;
    using DDataType            = typename Problem::DDataType;
    using AccDataType          = typename Problem::AccDataType;
    using ODataType            = typename Problem::ODataType;
    using AScaleDataType       = typename Problem::AScaleDataType;
    using GScaleDataType       = typename Problem::GScaleDataType;
    using DScaleDataType       = typename Problem::DScaleDataType;
    using YSmoothScaleDataType = typename Problem::YSmoothScaleDataType;
    using TopkWeightDataType   = typename Problem::TopkWeightDataType;
    using IndexDataType        = typename Problem::IndexDataType;
    using YDataType            = typename Problem::YDataType;

    using Traits = typename Problem::Traits;

    static constexpr bool IsGateOnly          = Traits::IsGateOnly;
    static constexpr bool UseSmoothQuant      = Traits::UseSmoothQuant;
    static constexpr bool PadHiddenSize       = Traits::PadHiddenSize;
    static constexpr bool PadIntermediateSize = Traits::PadIntermediateSize;

    static constexpr index_t kAlignmentA = Policy::template GetAlignment_A<Problem>();
    static constexpr index_t kAlignmentG = Policy::template GetAlignment_G<Problem>();
    static constexpr index_t kAlignmentD = Policy::template GetAlignment_D<Problem>();
    static constexpr index_t kAlignmentO = Policy::template GetAlignment_O<Problem>();
    static constexpr index_t NumPrefetch = Problem::NumPrefetch;

    static constexpr index_t SLD_A = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::SLD_A);
    static constexpr index_t GLD_A = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::GLD_A);
    static constexpr index_t GLD_B = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::GLD_B);
    static constexpr index_t GST_O = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::GST_O);

    static constexpr index_t kBlockPerCu = []() {
        if constexpr(Problem::kBlockPerCu != -1)
            return Problem::kBlockPerCu;
        else
        {
            // minimize occupancy
            return 2;
        }
    }();

    static constexpr const char* name = "fused_moe_flatmm";

    // TODO: there are multiple buffers
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_A()
    {
        return Policy::template GetSmemSize_A<Problem>();
    }

    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_D()
    {
        return Policy::template GetSmemSize_D<Problem>();
    }

    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize()
    {
        return Policy::template GetSmemSize<Problem>();
    }

    // this is the thread-offset along row/col
    CK_TILE_HOST_DEVICE static auto GetACoord()
    {
        constexpr auto a_dist = Policy::template MakeGlobalTileDistribution_A<Problem>();
        const auto a_coord    = a_dist.calculate_index(); // tile distribution index
        return a_coord;
    }

    // this is the thread-offset along row/col
    CK_TILE_HOST_DEVICE static auto GetOCoord()
    {
        constexpr auto o_dist = Policy::template MakeGlobalTileDistribution_O<Problem>();
        const auto o_coord    = o_dist.calculate_index();
        return o_coord;
    }

    template <typename AWindow,
              typename GWindow,
              typename DWindow,
              typename OWindow,
              typename TopkArrayType>
    CK_TILE_DEVICE auto
    operator()(const AWindow& a_window_,
               const GWindow& g_window_,
               const DWindow& d_window_,
               OWindow& o_window_,
               TopkArrayType& topk_weights /*topk_weight array for atomic, must be f32*/,
               CK_TILE_LDS_ADDR void* smem,
               index_t hidden_size,
               index_t intermediate_size
               // index_t stride_token
    )
    {
        _Pragma("clang diagnostic push") _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");
        constexpr auto I0 = number<0>{};
        constexpr auto I1 = number<1>{};
        constexpr auto I2 = number<2>{};
        constexpr auto I3 = number<3>{};

        CK_TILE_LDS_ADDR ADataType* smem_0 = reinterpret_cast<CK_TILE_LDS_ADDR ADataType*>(smem);

        auto g_view = g_window_.get_bottom_tensor_view();

        //
        auto u_view = [&]() {
            if constexpr(IsGateOnly)
            {
                // FIXME:
                static_assert(false, "GateOnly is not supported yet!");
                return g_view;
            }
            else
            {
                const GDataType* g_ptr =
                    g_window_.get_bottom_tensor_view().get_buffer_view().p_data_;

                const GDataType* u_ptr = g_ptr + intermediate_size * hidden_size;

                const auto u_view_ = make_naive_tensor_view<address_space_enum::global>(
                    u_ptr,
                    make_tuple(hidden_size/number<BlockShape::Block_K0>{}, number<BlockShape::Block_N0 * BlockShape::Block_K0>{}),
                    make_tuple(number<BlockShape::Block_K0 * BlockShape::Block_N0>{}, I1),
                    number<kAlignmentG>{},
                    number<1>{});

                // const auto u_view_1_ = pad_tensor_view(
                //     u_view_,
                //     make_tuple(number<BlockShape::Block_N0>{}, number<BlockShape::Block_K0>{}),
                //     sequence<PadIntermediateSize, PadHiddenSize>{});
                return u_view_;
            }
        }();

        // input global load to lds components
        auto a_copy_dram_window = make_tile_window(
            a_window_.get_bottom_tensor_view(),
            make_tuple(number<BlockShape::Block_M0>{}, number<BlockShape::Block_K0>{}),
            a_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_A<Problem>());
        constexpr auto a_copy_lds_block_desc = Policy::template MakeLdsStoreDesc_A<Problem>();
        constexpr auto a_lds_space_size      = ck_tile::integer_least_multiple(
            Policy::template GetSmemSize_A<Problem>(), BlockShape::Block_K0);
        // constexpr auto a_lds_bufs_elem_offset = 0;
        auto a_copy_lds_window0 = make_tile_window(
            make_tensor_view<address_space_enum::lds>(smem_0, a_copy_lds_block_desc),
            make_tuple(number<BlockShape::Block_M0>{}, number<BlockShape::Block_K0>{}),
            {0, 0});
        auto a_copy_lds_window1 = make_tile_window(
            make_tensor_view<address_space_enum::lds>(smem_0 + a_lds_space_size,
                                                      a_copy_lds_block_desc),
            make_tuple(number<BlockShape::Block_M0>{}, number<BlockShape::Block_K0>{}),
            {0, 0});
        auto a_copy_lds_windows = make_tuple(a_copy_lds_window0, a_copy_lds_window1);

        // gate load from global to vgpr then to lds components
        auto g_copy_dram_window = make_tile_window(
            g_window_.get_bottom_tensor_view(), // [hidden_states, moe_intermediate_size]
            make_tuple(I1,
                       number<BlockShape::Block_N0 * BlockShape::Block_K0>{}), //[BLOCK_N0, BLOKC_K0]
            g_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_G<Problem>());

        /*
        //if need write to lds, use this part
        constexpr auto g_copy_lds_block_desc            = Policy::template
        MakeLdsStoreDesc_G<Problem>(); constexpr auto g_lds_space_size                 =
        Policy::template GetSmemSize_G<Problem>(); constexpr auto g_lds_bufs_elem_offset           =
        a_lds_space_size * NumPrefetch; auto g_copy_lds_block                 =
        make_tensor_view<address_space_enum::lds>(smem_0 + a_lds_bufs_elem_offset,
                                                                                          g_copy_lds_block_desc);
        auto g_copy_lds_window = make_tile_window(
            g_copy_lds_block, make_tuple(number<BlockShape::Block_N0>{},
        number<BlockShape::Block_K0>{}), {0, 0});
        */

        // up proj reuse gate LDS and same as gate proj, all vgpr and lds layout
        auto u_copy_dram_window = make_tile_window(
            u_view,
            make_tuple(I1,
                       number<BlockShape::Block_N0 * BlockShape::Block_K0>{}), //[KIter, BLOCK]
            {0, 0},
            Policy::template MakeGlobalTileDistribution_G<Problem>());
        /*
        // For LDS flow
        constexpr auto u_copy_lds_block_desc            = Policy::template
        MakeLdsStoreDesc_G<Problem>(); constexpr auto u_lds_space_size                 =
        Policy::template GetSmemSize_G<Problem>(); constexpr auto g_lds_bufs_elem_offset           =
        a_lds_space_size * NumPrefetch; auto g_copy_lds_block                 =
        make_tensor_view<address_space_enum::lds>(smem_0 + a_lds_bufs_elem_offset,
                                                                                          g_copy_lds_block_desc);
        auto g_copy_lds_window = make_tile_window(
            g_copy_lds_block, make_tuple(number<BlockShape::Block_N0>{},
        number<BlockShape::Block_K0>{}), {0, 0});
        */

        // gemm0 from LDS to VGPR
        // TODO: support get_sub_warp_id for WASP
        using WarpGemm0  = decltype(Policy::template GetWarpGemm0<Problem>());
        auto warp_gemm_0 = WarpGemm0{};
        // input
        // tile_windows here are for warps
        constexpr auto a_gemm_sld_block_desc = Policy::template MakeLdsLoadDesc_A<Problem>();
        auto a_sld_win0                      = [&]() {
            using WG = WarpGemm0;
            auto a_gemm_sld_block =
                make_tensor_view<address_space_enum::lds>(smem_0, a_gemm_sld_block_desc);
            return make_tile_window(
                a_gemm_sld_block,
                a_gemm_sld_block_desc.get_lengths(),
                {0, 0},
                make_static_tile_distribution(typename WG::AWarpDstrEncoding{}));
        }();
        auto a_sld_win1 = [&]() { // Prefetch window
            using WG              = WarpGemm0;
            auto a_gemm_sld_block = make_tensor_view<address_space_enum::lds>(
                smem_0 + a_lds_space_size, a_gemm_sld_block_desc);
            return make_tile_window(
                a_gemm_sld_block,
                a_gemm_sld_block_desc.get_lengths(),
                {0, 0},
                make_static_tile_distribution(typename WG::AWarpDstrEncoding{}));
        }();

        // weight
        /*
        //TODO: Enable for LDS solution
        constexpr auto gu_gemm_sld_block_desc = Policy::template MakeLdsLoadDesc_G<Problem>();
        auto gu_gemm_sld_block           = make_tensor_view<address_space_enum::lds>(smem_0 +
        g_lds_bufs_elem_offset, g_gemm_sld_block_desc); auto gu_gemm_sld_block_window    =
        make_tile_window(g_gemm_sld_block, g_gemm_sld_block_desc.get_lengths(), {0, 0}); warp window
        auto gu_sld_win = [&](){
            using WG                        = WarpGemm0;
            return make_tile_window(
                gu_gemm_sld_block_window.get_bottom_tensor_view(),
                make_tuple(number<WG::kN>{}, number<WG::kK>{}),
                gu_gemm_sld_block_window.get_window_origin() + multi_index<2>{iNWarp * WG::kN, 0},
                make_static_tile_distribution(typename WG::BWarpDstrEncoding{}));
        }();
        */

        // gemm1 weight global to vgpr
        // TODO: replace buffer vgpr to buffer lds
        // auto d_copy_dram_window = make_tile_window(
        //     d_window_.get_bottom_tensor_view(), // [hidden_states, moe_intermediate_size]
        //     make_tuple(number<BlockShape::Block_N0>{},
        //                number<BlockShape::Block_K0>{}), //[BLOCK_N0, BLOKC_K0]
        //     d_window_.get_window_origin(),
        //     Policy::template MakeGlobalTileDistribution_D<Problem>());

        auto d_copy_dram_window = make_tile_window(
            d_window_.get_bottom_tensor_view(), // [hidden_states, moe_intermediate_size]
            make_tuple(number<BlockShape::Block_N1>{}, number<BlockShape::Block_K1>{}),
            d_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_D<Problem>());

        // gemm 1 vgpr to lds
        // CK_TILE_LDS_ADDR DDataType* smem_1   = reinterpret_cast<CK_TILE_LDS_ADDR
        // DDataType*>(smem); constexpr auto d_copy_lds_block_desc = Policy::template
        // MakeLdsStoreDesc_D<Problem>(); auto d_copy_lds_block =
        //     make_tensor_view<address_space_enum::lds>(smem_1, d_copy_lds_block_desc);
        // auto d_copy_lds_block2 =
        //     make_tensor_view<address_space_enum::lds>(smem_1 + Policy::template
        //     GetSmemSize_D<Problem>(), d_copy_lds_block_desc);
        // auto d_copy_lds_window = make_tile_window(
        //     d_copy_lds_block,
        //     make_tuple(number<BlockShape::Block_N1>{},
        //         Problem::IsSwizzled ? number<BlockShape::Block_K1 / 2>{} :
        //         number<BlockShape::Block_K1>{}),
        //     {0, 0});
        // auto d_copy_lds_window2 = make_tile_window(
        //     d_copy_lds_block2,
        //     make_tuple(number<BlockShape::Block_N1>{}, number<BlockShape::Block_K1 / 2>{}),
        //     {0, 0});

        // gemm1 lds to vgpr
        using WarpGemm1  = decltype(Policy::template GetWarpGemm1<Problem>());
        auto warp_gemm_1 = WarpGemm1{};

        // auto d_gemm_sld_block_desc = Policy::template MakeLdsLoadDesc_D<Problem>();
        // auto d_sld_win             = [&]() {
        //     using WG                        = WarpGemm1;
        //     constexpr auto d_outer_dstr_enc = tile_distribution_encoding<
        //         sequence<>,
        //         tuple<sequence<BlockShape::Repeat_N1, BlockShape::WarpPerBlock_N1>,
        //               sequence<BlockShape::Repeat_K1>>,
        //         tuple<sequence<1>>,
        //         tuple<sequence<1>>,
        //         sequence<1, 2>,
        //         sequence<0, 0>>{};
        //     constexpr auto d_block_dstr_encode = detail::make_embed_tile_distribution_encoding(
        //         d_outer_dstr_enc, typename WG::BWarpDstrEncoding{});
        //     auto d_gemm_sld_block =
        //         make_tensor_view<address_space_enum::lds>(smem_1, d_gemm_sld_block_desc);
        //     auto d_gemm_sld_win =
        //         make_tile_window(d_gemm_sld_block,
        //                          d_gemm_sld_block_desc.get_lengths(),
        //                          {0, 0},
        //                          make_static_tile_distribution(d_block_dstr_encode));
        //     return d_gemm_sld_win;
        // }();

        // auto d_sld_win2             = [&]() {
        //     using WG                        = WarpGemm1;
        //     constexpr auto d_outer_dstr_enc = tile_distribution_encoding<
        //         sequence<>,
        //         tuple<sequence<BlockShape::Repeat_N1, BlockShape::WarpPerBlock_N1>,
        //               sequence<BlockShape::Repeat_K1>>,
        //         tuple<sequence<1>>,
        //         tuple<sequence<1>>,
        //         sequence<1, 2>,
        //         sequence<0, 0>>{};
        //     constexpr auto d_block_dstr_encode = detail::make_embed_tile_distribution_encoding(
        //         d_outer_dstr_enc, typename WG::BWarpDstrEncoding{});
        //     auto d_gemm_sld_block =
        //         make_tensor_view<address_space_enum::lds>(smem_1 + Policy::template
        //         GetSmemSize_D<Problem>(), d_gemm_sld_block_desc);
        //     auto d_gemm_sld_win =
        //         make_tile_window(d_gemm_sld_block,
        //                          d_gemm_sld_block_desc.get_lengths(),
        //                          {0, 0},
        //                          make_static_tile_distribution(d_block_dstr_encode));
        //     return d_gemm_sld_win;
        // }();

        constexpr index_t atomic_issues = BlockShape::Block_M1 / number<4>{};
        auto o_windows                  = generate_tuple(
            [&](auto i) {
                return make_tile_window(o_window_[i],
                                        Policy::template MakeGlobalTileDistribution_O<Problem>());
            },
            number<atomic_issues>{});

        auto bridge_sst_win = [&]() {
            return make_tile_window(
                make_tensor_view<address_space_enum::lds>(
                    reinterpret_cast<YDataType*>(smem),
                    Policy::template MakeBridgeLdsStoreDesc<Problem>()),
                Policy::template MakeBridgeLdsStoreDesc<Problem>().get_lengths(),
                {0, 0});
        }();

        auto bridge_sld_win = [&]() {
            return make_tile_window(make_tensor_view<address_space_enum::lds>(
                                        reinterpret_cast<YDataType*>(smem),
                                        Policy::template MakeBridgeLdsLoadDesc<Problem>()),
                                    Policy::template MakeBridgeLdsLoadDesc<Problem>().get_lengths(),
                                    {0, 0},
                                    Policy::template MakeYTileDistribution<Problem>());
        }();
        auto bridge_sld_win2 = [&]() {
            return make_tile_window(make_tensor_view<address_space_enum::lds>(
                                        reinterpret_cast<YDataType*>(smem),
                                        Policy::template MakeBridgeLdsLoadDesc<Problem>()),
                                    Policy::template MakeBridgeLdsLoadDesc<Problem>().get_lengths(),
                                    {0, number<BlockShape::Block_K1 / 2>{}},
                                    Policy::template MakeYTileDistribution<Problem>());
        }();

        // also OK with C array, 2 register buffer, prefetch u or prefetch g
        // statically_indexed_array<g_thread_type, 2> gs;

        // constexpr auto issues_a = number<a_copy_dram_window.get_num_of_access()>{};
        constexpr auto issues_g = number<g_copy_dram_window.get_num_of_access()>{};
        // constexpr auto issues_d = number<d_copy_dram_window.get_num_of_access()>{};
        // constexpr auto issues_d = number<d_win.get_num_of_access()>{};
        // constexpr auto issues_o = number<o_win.get_num_of_access()>{};

        const index_t num_blocks_k0 =
            (hidden_size + BlockShape::Block_K0 - 1) / BlockShape::Block_K0;
        const index_t num_blocks_n1 =
            (hidden_size + BlockShape::Block_N1 - 1) / BlockShape::Block_N1;

        using a_thread_type = decltype(load_tile(a_sld_win0));
        using g_thread_type = decltype(load_tile(g_copy_dram_window));
        using d_thread_type = decltype(load_tile(d_copy_dram_window));
        // using sld_d_thread_type = decltype(load_tile(d_sld_win));
        statically_indexed_array<a_thread_type, 1> a;
        statically_indexed_array<g_thread_type, 4> gs;
        statically_indexed_array<d_thread_type, 2> gd;
        // statically_indexed_array<sld_d_thread_type,1> sd;

        auto gld_a_init = [&]() { a_copy_dram_window.init_raw(); };

        auto gld_a = [&](auto& a_store_) {
            async_load_tile_by_inline_asm(a_store_, a_copy_dram_window);
        };
        auto move_a = [&]() {
            move_tile_window(a_copy_dram_window, {number<0>{}, number<BlockShape::Block_K0>{}});
        };
        auto sld_a = [&](auto& a_, auto& win_) { load_tile(a_, win_); };

        auto gld_g_init = [&]() { g_copy_dram_window.init_raw(); };

        auto gld_g = [&](auto& g_) {
            if constexpr(IsGateOnly)
            {
                // TODO
            }
            load_tile(g_, g_copy_dram_window);
        };
        auto move_g = [&]() {
            move_tile_window(g_copy_dram_window, {I1, I0});
        };

        auto gld_u_init = [&]() { u_copy_dram_window.init_raw(); };

        auto gld_u = [&](auto& u_) {
            if constexpr(IsGateOnly)
            {
                load_tile(u_, g_copy_dram_window);
            }
            else
            {
                load_tile(u_, u_copy_dram_window);
            }
        };
        auto move_u = [&]() {
            if constexpr(IsGateOnly)
            {
                move_tile_window(g_copy_dram_window, {I1, I0});
            }
            else
            {
                move_tile_window(u_copy_dram_window, {I1, I0});
            }
        };
        // statically_indexed_array<d_thread_type, 2> ds;
        auto gld_d_init = [&]() { d_copy_dram_window.init_raw(); };
        auto gld_d      = [&](auto& d_1) { load_tile(d_1, d_copy_dram_window); };
        auto move_d     = [&]() {
            // d move along gemm-n
            move_tile_window(d_copy_dram_window, {number<BlockShape::Block_N1>{}, number<0>{}});
        };

        auto atomic_add_o = [&](auto& o_) {
            using WarpGemm = typename remove_cvref_t<decltype(warp_gemm_1)>::WarpGemmAttribute;

            // o_is
            // get atomic element from gemm1 output and write out in single buffer issue
            // FIXME: support NRepeat(warp gemm)/ Repeat_N0 not equal with 1.
            static_for<0, atomic_issues, 1>{}([&](auto i) {
                using o_thread_type = decltype(load_tile(o_windows[i]));
                o_thread_type output_tmp_buf;
                constexpr auto c_warp_y_index   = sequence<i / (WarpGemm::MRepeat * 4), // Repeat_M1
                                                         0,                           // Repeat_N1
                                                         i / 4 % 4,                   // MRepeat
                                                         0,                           // NRepeat
                                                         0,     // MInterleave
                                                         0,     // NInterleave
                                                         0,     // NPerlane
                                                         i % 4, // M0PerLane
                                                         0>{};  // M1PerLane
                constexpr auto c_warp_y_lengths = to_sequence(
                    output_tmp_buf.get_tile_distribution().get_ys_to_d_descriptor().get_lengths());
                output_tmp_buf.get_thread_buffer() =
                    o_.get_y_sliced_thread_data(c_warp_y_index, c_warp_y_lengths);
                sweep_tile(output_tmp_buf, [&](auto idx0) {
                    output_tmp_buf(idx0) = output_tmp_buf(idx0) * topk_weights[i];
                });
                update_tile(o_windows[i], output_tmp_buf); // 1xbuffer atomic issue
                move_tile_window(o_windows[i], {number<0>{}, number<BlockShape::Block_N1>{}});
            });
        };

        // tuple(gate, up)
        auto acc_0 = make_tuple(Policy::template MakeCBlockTile_Gemm0<Problem>(),
                                Policy::template MakeCBlockTile_Gemm0<Problem>());
        // auto acc_1 = Policy::template MakeCBlockTile_Gemm1<Problem>();
        auto acc_1s = generate_tuple(
            [&](auto) { return Policy::template MakeCBlockTile_Gemm1<Problem>(); }, number<2>{});

        // clang-format off
        //t_c refers to all gate/up_proj results in 1 thread.(VGPR), t_a, t_b have similar meaning.
        auto gemm_0 = [&](auto& t_c, auto& t_a, auto& t_b) {
            using WarpGemm = remove_cvref_t<decltype(warp_gemm_0)>;

            using AWarpTensor = typename WarpGemm::AWarpTensor;
            using BWarpTensor = typename WarpGemm::BWarpTensor;
            using CWarpTensor = typename WarpGemm::CWarpTensor;
            using CWarpDstr = typename WarpGemm::CWarpDstr;

            constexpr auto c_warp_y_index_zeros = uniform_sequence_gen_t<CWarpDstr::NDimY, 0>{};
            constexpr auto c_warp_y_lengths = to_sequence(CWarpDstr{}.get_ys_to_d_descriptor().get_lengths());

            //w_a is same as t_a
            AWarpTensor w_a;
            w_a.get_thread_buffer() = t_a.get_thread_buffer();

            //w_b is same as t_b due to t_b has N x K = 4 x 8 
            BWarpTensor w_b;
            w_b.get_thread_buffer() = t_b.get_thread_buffer();
            CWarpTensor w_c;

            //t_c is blockwise tensor, has repeat and warps. 0,0 here refers to m,n repeat for now only 1 is supported
            // <0,0,0,2> -> offset
            w_c.get_thread_buffer() = t_c.get_y_sliced_thread_data(
                        merge_sequences(sequence<0, 0>{}, c_warp_y_index_zeros),
                        merge_sequences(sequence<1, 1>{}, c_warp_y_lengths));
            warp_gemm_0(w_c, w_a, w_b);
            
            //direct copy, we may use set_thread_buffer?
            //Note: Layout here is MRepeat=2, NRpeat=4(4interleave)
            t_c.set_y_sliced_thread_data(
                        merge_sequences(sequence<0, 0>{}, c_warp_y_index_zeros),
                        merge_sequences(sequence<1, 1>{}, c_warp_y_lengths),
                        w_c.get_thread_buffer());
        };
        // clang-format on

        // clang-format off
        auto gemm_1 = [&](auto& t_c, auto& t_a, auto& t_b) {
            using WarpGemm = remove_cvref_t<decltype(warp_gemm_1)>;

            using AWarpTensor = typename WarpGemm::AWarpTensor;
            using BWarpTensor = typename WarpGemm::BWarpTensor;
            using CWarpTensor = typename WarpGemm::CWarpTensor;
            using CWarpDstr = typename WarpGemm::CWarpDstr;

            constexpr auto c_warp_y_index_zeros = uniform_sequence_gen_t<CWarpDstr::NDimY, 0>{};
            constexpr auto c_warp_y_lengths = to_sequence(CWarpDstr{}.get_ys_to_d_descriptor().get_lengths());

            //w_a is same as t_a
            AWarpTensor w_a;
            w_a.get_thread_buffer() = t_a.get_thread_buffer();

            //w_b is same as t_b due to t_b has N x K = 4 x 8 
            BWarpTensor w_b;
            w_b.get_thread_buffer() = t_b.get_thread_buffer();
            CWarpTensor w_c;
            //t_c is blockwise tensor, has repeat and warps. 0,0 here refers to m,n repeat for now only 1 is supported
            w_c.get_thread_buffer() = t_c.get_y_sliced_thread_data(
                        merge_sequences(sequence<0, 0>{}, c_warp_y_index_zeros),
                        merge_sequences(sequence<1, 1>{}, c_warp_y_lengths));
            warp_gemm_1(w_c, w_a, w_b);
            
            //direct copy
            t_c.set_y_sliced_thread_data(
                        merge_sequences(sequence<0, 0>{}, c_warp_y_index_zeros),
                        merge_sequences(sequence<1, 1>{}, c_warp_y_lengths),
                        w_c.get_thread_buffer());
        };
        // clang-format on
        _Pragma("clang diagnostic pop");

        auto pipeline_gemm0 = [&]() {
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);
            __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            sld_a(a[I0], a_sld_win0);
            gld_a(a_copy_lds_windows(I1));
            __builtin_amdgcn_sched_barrier(0);

            move_a();
            gld_g(gs[I2]);
            move_g();
            gld_u(gs[I3]);
            move_u();

            // pre-load a and next u/g
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);

            // first mmac group
            gemm_0(acc_0[I0], a[I0], gs[I0]);
            gemm_0(acc_0[I1], a[I0], gs[I1]);

            // second mmac group
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);
            __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            sld_a(a[I0], a_sld_win1);
            gld_a(a_copy_lds_windows(I0));
            __builtin_amdgcn_sched_barrier(0);

            move_a();
            gld_g(gs[I0]);
            move_g();
            gld_u(gs[I1]);
            move_u();
            __builtin_amdgcn_s_setprio(1);

            gemm_0(acc_0[I0], a[I0], gs[I2]);
            gemm_0(acc_0[I1], a[I0], gs[I3]);
        };

        auto pipeline_gemm0_tail = [&]() {
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);
            __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            sld_a(a[I0], a_sld_win0);
            gld_a(a_copy_lds_windows(I1));
            __builtin_amdgcn_sched_barrier(0);
            gld_g(gs[I2]);
            gld_u(gs[I3]);

            // pre-load a and next u/g
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);

            // first mmac group
            gemm_0(acc_0[I0], a[I0], gs[I0]);
            gemm_0(acc_0[I1], a[I0], gs[I1]);

            // second mmac group
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);
            __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            sld_a(a[I0], a_sld_win1);

            // block_sync_load_raw(issues_a + 2 * issues_g);
            __builtin_amdgcn_s_setprio(1);
            gemm_0(acc_0[I0], a[I0], gs[I2]);
            gemm_0(acc_0[I1], a[I0], gs[I3]);
            __builtin_amdgcn_sched_barrier(0);
        };

        auto y  = Policy::template MakeYBlockTile<Problem>();
        auto y2 = Policy::template MakeYBlockTile<Problem>();

        auto pipeline_bridge = [&]() {
            using WarpGemm  = remove_cvref_t<decltype(warp_gemm_0)>;
            using CDataType = typename WarpGemm::CDataType;
            if constexpr(IsGateOnly)
            {
                static_assert(false, "not supported yet");
            }
            else
            {
                block_sync_lds(); // ensure last input load have been read from lds
                sweep_tile(
                    acc_0.at(number<0>{}),
                    [&](auto idx0, auto idx1) {
                        fp32x2_t v_{acc_0.at(number<0>{})(idx0), acc_0.at(number<0>{})(idx1)};
                        typename Problem::GateActivation{}(v_, v_);
                        acc_0.at(number<0>{})(idx0) = v_.x;
                        acc_0.at(number<0>{})(idx1) = v_.y;
                    },
                    sequence<1, 2>{}); // m=1, n=4 continuos element in thread_buffer(VGPR)
                // mul
                auto reduce_acc_0 =
                    tile_elementwise_in([&](const auto& a_, const auto& b_) { return a_ * b_; },
                                        acc_0.at(number<0>{}),
                                        acc_0.at(number<1>{}));

                constexpr auto bridge_tile_enc =
                    Policy::template MakeBridgeTileDistribution<Problem>();

                auto bridge_tile_tensor =
                    make_static_distributed_tensor<CDataType>(bridge_tile_enc);
                static_assert(bridge_tile_tensor.get_thread_buffer_size() ==
                                  reduce_acc_0.get_thread_buffer_size(),
                              "bridge tensor is not same as reduce tensor!");

                constexpr index_t thread_buf_size = bridge_tile_tensor.get_thread_buffer_size();
                // Note: here we assume that every mmac output 4 element, and NInterleave mmac will
                // merge together. So here 1 group refers to 4 x NInterleave.
                static_for<0, thread_buf_size, 1>{}([&](auto i) {
                    index_t reduce_index =
                        (i / (Problem::Gemm0NInterleave * 4)) * (Problem::Gemm0NInterleave * 4) +
                        (i % (Problem::Gemm0NInterleave * 4)) / Problem::Gemm0NInterleave +
                        i % Problem::Gemm0NInterleave * 4;
                    bridge_tile_tensor.get_thread_buffer()[i] =
                        reduce_acc_0.get_thread_buffer()[reduce_index];
                });

                // TODO: support i8 quant here
                // auto y_pre = cast_tile<YDataType>(bridge_tile_tensor);
                store_tile(bridge_sst_win, cast_tile<YDataType, false>(bridge_tile_tensor));
                clear_tile(acc_1s(I0));
                block_sync_lds();
                // wave_barrier();
                load_tile(y, bridge_sld_win);
                if constexpr(Problem::IsSwizzled)
                {
                    load_tile(y2, bridge_sld_win2);
                }
                clear_tile(acc_1s(I1));
                block_sync_lds();
                __builtin_amdgcn_sched_barrier(0);
            }
        };

        // note, gemm-1 start from idx-1 to N-2 (0, 1, 2....N-1)
        auto pipeline_gemm1 = [&]() {
            // block_sync_load_raw(issues_d);
            gld_d(gd[I1]);
            move_d();
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);
            gemm_1(acc_1s[I0], y, gd[I0]);
            atomic_add_o(acc_1s[I0]);
            // block_sync_lds();
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);

            // Note: if support pk_atomic_add, here will use 2interleave and f16 atomic
            // move_o();
            // block_sync_load_raw(issues_d);
            gld_d(gd[I0]);
            move_d();
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);

            gemm_1(acc_1s[I1], y, gd[I1]);
            atomic_add_o(acc_1s[I1]);

            __builtin_amdgcn_s_setprio(0);

            clear_tile(acc_1s(I0));
            clear_tile(acc_1s(I1));
            // block_sync_lds();
            // asm volatile("s_waitcnt vmcnt(0)");
            __builtin_amdgcn_sched_barrier(0);
        };

        auto pipeline_gemm1_head = [&]() {
            gld_d_init();
            gld_d(gd[I0]);
            move_d();
        };
        auto pipeline_gemm1_tail = [&]() {
            // block_sync_load_raw(issues_d);
            gld_d(gd[I1]);
            move_d();

            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);
            gemm_1(acc_1s[I0], y, gd[I0]);

            atomic_add_o(acc_1s[I0]);
            // block_sync_lds();

            __builtin_amdgcn_sched_barrier(0);
            // block_sync_load_raw(issues_d);
            gemm_1(acc_1s[I1], y, gd[I1]);
            atomic_add_o(acc_1s[I1]);

            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
        };

        // start of pipeline
        // clang-format off
        gld_a_init();
        gld_a(a_copy_lds_windows(I0));
        move_a();
        //quant
        gld_g_init();
        gld_u_init();
        gld_g(gs[I0]);
        move_g();
        gld_u(gs[I1]);
        move_u();
        //b scale load
        clear_tile(acc_0.at(I0));
        clear_tile(acc_0.at(I1));


        // make sure a,g loaded
        // lds_load_fence();
        // block_sync_load_raw(2 * issues_g);

        // we manually unroll double buffer inside hot loop
        const index_t iters_0 = (num_blocks_k0 - 2) / 2;
        index_t i_0 = 0; // (void)i_0; (void)iters_0; (void)pipeline_gemm0;
        while(i_0++ < iters_0)
        {
            pipeline_gemm0();
        }
        pipeline_gemm0_tail();

        pipeline_bridge();

        const index_t iters_1 = (num_blocks_n1 - 2) / 2;
        index_t i_1 = 0; // (void) i_1; (void)iters_1; (void)pipeline_gemm1;
        pipeline_gemm1_head();
        while(i_1++ < iters_1)
        {
            pipeline_gemm1();
        }
        pipeline_gemm1_tail();
        // clang-format on
    }
};

} // namespace ck_tile
