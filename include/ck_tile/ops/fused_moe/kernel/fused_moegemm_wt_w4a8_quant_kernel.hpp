// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/elementwise.hpp"
#include "ck_tile/ops/fused_moe/kernel/fused_moegemm_kernel.hpp"
#include <string>
#include <type_traits>


namespace ck_tile {

// This is scatter/gather b2b group-gemm
template <typename Partitioner_, typename Pipeline_, typename Epilogue_>
struct FusedMoeGemmWWtW4A8QuantKernel
{
    using Partitioner = remove_cvref_t<Partitioner_>;
    using Pipeline    = remove_cvref_t<Pipeline_>;
    using Epilogue    = remove_cvref_t<Epilogue_>; // TODO: not used
    // static constexpr index_t kBlockPerCu = Pipeline::kBlockPerCu;
    // static_assert(kBlockPerCu > 0);

    using Problem = remove_cvref_t<typename Pipeline::Problem>;
    using BlockShape = typename Pipeline::BlockShape; // this is FusedMoeGemmShape
    static constexpr index_t BlockSize_ = BlockShape::BlockSize;

    using ADataType            = typename Problem::ADataType;
    using GDataType            = typename Problem::GDataType;
    using DDataType            = typename Problem::DDataType;
    using AccDataType          = typename Problem::AccDataType;
    using ODataType            = typename Problem::ODataType;
    using AQuantDataType       = typename Problem::GDataType;
    using AScaleDataType       = typename Problem::AScaleDataType;
    using GScaleDataType       = typename Problem::GScaleDataType;
    using DScaleDataType       = typename Problem::DScaleDataType;
    using GZeroPointDataType   = typename Problem::GZeroPointDataType;
    using DZeroPointDataType   = typename Problem::DZeroPointDataType;
    using YSmoothScaleDataType = typename Problem::YSmoothScaleDataType;
    using TopkWeightDataType   = typename Problem::TopkWeightDataType;
    using IndexDataType        = typename Problem::IndexDataType;
    using YDataType            = typename Problem::YDataType;

    using Traits                = typename Problem::Traits;
    static constexpr bool UseUK = false;

    static constexpr bool IsGateOnly          = Traits::IsGateOnly;
    static constexpr bool UseSmoothQuant      = Traits::UseSmoothQuant;
    static constexpr bool PadHiddenSize       = Traits::PadHiddenSize;
    static constexpr bool PadIntermediateSize = Traits::PadIntermediateSize;
    static constexpr index_t Fused_quant_type = Problem::FusedQuant;     // 0:no-sweep, 1:smooth-dynamic-quant, 2:int8_w8a16, 3:int4_w4a16, 4:use_int8_w8a8_block, 5:use_int4_w4a8_block, 10:dynamic-quant

    static constexpr index_t Block_N0_P =  BlockShape::Block_N0 / Problem::PackFactor;
    static constexpr index_t Block_K0_P =  BlockShape::Block_K0 / Problem::PackFactor;
    static constexpr index_t Block_N1_P =  BlockShape::Block_N1 / Problem::PackFactor;
    static constexpr index_t Block_K1_P =  BlockShape::Block_K1 / Problem::PackFactor;

    static constexpr index_t Block_K0_Group =  BlockShape::Block_K0 / Problem::QuantBlockSizeK;
    static constexpr index_t Block_K1_Group =  BlockShape::Block_K1 / Problem::QuantBlockSizeK;

    // clang-format off
    template <typename T> struct t2s;
    template <> struct t2s<float> { static constexpr const char * name = "fp32"; };
    template <> struct t2s<fp16_t> { static constexpr const char * name = "fp16"; };
    template <> struct t2s<bf16_t> { static constexpr const char * name = "bf16"; };
    template <> struct t2s<fp8_t> { static constexpr const char * name = "fp8"; };
    template <> struct t2s<bf8_t> { static constexpr const char * name = "bf8"; };
    template <> struct t2s<int8_t> { static constexpr const char * name = "int8"; };
    template <> struct t2s<uint8_t> { static constexpr const char * name = "uint8"; };
    // clang-format on

    CK_TILE_HOST static std::string GetName()
    {
#define _SS_ std::string
#define _TS_ std::to_string
        // clang-format off
        using S_ = BlockShape;

        auto prec_str = [&] () {
            std::string base_str = _SS_(t2s<ADataType>::name);
            if (!std::is_same_v<ADataType, GDataType>) {
                base_str += _SS_("_") + _SS_(t2s<GDataType>::name);
            }
            return base_str;
        }();

        return _SS_("fused_moe_") + _SS_(prec_str) + "_" + (IsGateOnly ? "g1u0_":"g1u1_") +
             _TS_(S_::Block_M0) + "x" + _TS_(S_::Block_N0) + "x" + _TS_(S_::Block_K0) + "x" + _TS_(S_::Block_N1) + "_" +
             _TS_(S_::WarpPerBlock_M0) + "x" + _TS_(S_::WarpPerBlock_N0) + "x" + _TS_(S_::WarpPerBlock_K0) + "_" +
             _TS_(S_::Warp_M0) + "x" + _TS_(S_::Warp_N0) + "x" + _TS_(S_::Warp_K0) + "_" + _SS_(Pipeline::name);
#undef _SS_
#undef _TS_
        // clang-format on
    }

    struct FusedMoeGemmKargs
    {
        const void* a_ptr;              // [m, k], input token
        const void* a_scale_ptr;        // [m, 1], token scale
        const void* g_ptr;              // [e, n, k]/[e, 2*n, k], pre-shuffle([e, nr, kr, w])
        const void* d_ptr;              // [e, n, k], pre-shuffle([e, nr, kr, w])
        const void* g_scale_ptr;        // [e, 1, n], gate(up) scale
        const void* d_scale_ptr;        // [e, 1, k], down scale
        const void* g_zp_ptr;           // [e, 2*n, k/group], gate(up) zero-point
        const void* d_zp_ptr;           // [e, k, n/group], down zero-point
        const void* y_smooth_scale_ptr; // [e, 1, n], smooth-quant-scale for 2nd gemm input
        void* o_ptr;                    // [m, k], output token
        void* deterministic_tmp_ptr;    // reserved for standard topk=1 kernel
        void* deterministic_counter_ptr;

        const void* sorted_token_ids_ptr;
        const void* sorted_weight_ptr;
        const void* sorted_expert_ids_ptr;
        const void* num_sorted_tiles_ptr;
        // void* tmp_out;                  // tempary output

        index_t hidden_size;       // k
        index_t intermediate_size; // n / TP, for Gate/Up/Down
        index_t num_tokens;        // input number of tokens for current iteration
        index_t num_experts;       // number of groups
        index_t topk;              // need this?

        index_t stride_token; // for input/output, stride for each row, should >= hidden_size
        index_t block_shape_n;
        index_t block_shape_k;
    };

    // TODO: switch karg based on
    using Kargs = FusedMoeGemmKargs;
    using Hargs = FusedMoeGemmHostArgs;

    CK_TILE_HOST static constexpr Kargs MakeKargs(const Hargs& hargs)
    {
        // TODO: hargs/kargs not guranteed to be the same
        return bit_cast<Kargs>(hargs);
    }

    CK_TILE_HOST static constexpr auto GridSize(const Hargs& hargs)
    {
        constexpr index_t block_m = BlockShape::Block_M0;
        int max_num_tokens_padded =
            hargs.topk * hargs.num_tokens + hargs.num_experts * block_m - hargs.topk;
        // printf("xxx max_num_tokens_padded:%d\n", max_num_tokens_padded);
        return Partitioner::GridSize(max_num_tokens_padded, hargs.intermediate_size);
    }

    CK_TILE_HOST static constexpr auto BlockSize() { return dim3(BlockSize_); }

    CK_TILE_HOST_DEVICE static constexpr index_t GetSmemSize() { return Pipeline::GetSmemSize(); }

    CK_TILE_DEVICE void operator()(Kargs kargs) const
    {
        if constexpr(UseUK)
        {
            static_assert(false, "ASM version not supported yet!");
        }
        else
        {
            _Pragma("clang diagnostic push")
                _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");
            // allocate LDS
            // __shared__ char smem_ptr[GetSmemSize()];
            IndexDataType num_sorted_tiles = __builtin_amdgcn_readfirstlane(
                *reinterpret_cast<const IndexDataType*>(kargs.num_sorted_tiles_ptr));
            constexpr index_t hidden_radio_0 = IsGateOnly ? 1 : 2; // gate_up=2

            index_t hidden_size_packed =  kargs.hidden_size / Problem::PackFactor;
            index_t intermediate_size_packed = kargs.intermediate_size / Problem::PackFactor;

            index_t expert_stride_0 = kargs.intermediate_size * hidden_radio_0 * hidden_size_packed;
            index_t expert_stride_1 = intermediate_size_packed * kargs.hidden_size;

            index_t hidden_size_group = kargs.hidden_size / Problem::QuantBlockSizeK;
            index_t intermediate_size_group = kargs.intermediate_size / Problem::QuantBlockSizeK;

            index_t expert_stride_sc_0 = kargs.intermediate_size * hidden_radio_0 * hidden_size_group;
            index_t expert_stride_sc_1 = intermediate_size_group * kargs.hidden_size;

            index_t expert_stride_zp_0 = intermediate_size_packed * hidden_radio_0 * hidden_size_group;
            index_t expert_stride_zp_1 = intermediate_size_group * hidden_size_packed;

            __shared__ CK_TILE_LDS_ADDR ADataType smem[GetSmemSize()];
            __shared__ CK_TILE_LDS_ADDR char smem_quant_inter[Pipeline::GetQuantPipeSmemSize()];
            __shared__ CK_TILE_LDS_ADDR AQuantDataType smem_quant[Pipeline::GetSmemSize_quant_out()];
            __shared__ CK_TILE_LDS_ADDR AScaleDataType smem_scale[Pipeline::GetSmemSize_scale_out()];

            // note this is in unit of tile, need multiple tile size to get the index
            num_sorted_tiles = num_sorted_tiles / BlockShape::Block_M0;
            // printf("num_sorted_tiles:%d \n",num_sorted_tiles);
            const auto [sorted_tile_id, intermediate_tile_id] =
                Partitioner{}(num_sorted_tiles, kargs.intermediate_size);
            if(sorted_tile_id >= num_sorted_tiles)
                return;

            const IndexDataType expert_id =
                __builtin_amdgcn_readfirstlane(reinterpret_cast<const IndexDataType*>(
                    kargs.sorted_expert_ids_ptr)[sorted_tile_id]);

            // index along intermediate_size
            index_t hidden_idx =
                __builtin_amdgcn_readfirstlane(intermediate_tile_id * BlockShape::Block_N0);
            
            index_t hidden_idx_packed = hidden_idx / Problem::PackFactor;

            const auto a_coord = Pipeline::GetACoord(); // 2d thread offset, [i_row, i_col]
            const auto sorted_token_id =
                a_coord[number<0>{}] + sorted_tile_id * BlockShape::Block_M0;

            index_t token_id =
                reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr)[sorted_token_id];
#if CK_TILE_REFERENCE_MOE_SORTING_MOCK_ID  || CK_TILE_REFERENCE_MOE_SORTING_MOCK_EXPERT_ID
            token_id &= 0xffffff;
#endif

            const auto a_window = [&]() {
                // A is already pre-padded in previous kernel
                const ADataType* a_ptr = reinterpret_cast<const ADataType*>(kargs.a_ptr);
                const auto a_view_     = make_naive_tensor_view<address_space_enum::global>(
                    a_ptr,
                    make_tuple(kargs.num_tokens, kargs.hidden_size),
                    make_tuple(kargs.stride_token, 1),
                    number<Pipeline::kAlignmentA>{},
                    number<1>{});

                // gather is here use indexing transform
                // Here choose actual token accoding sorted_token_id
                const auto a_gather_view_ = transform_tensor_view(
                    a_view_,
                    make_tuple(make_indexing_transform(kargs.num_tokens, token_id),
                               make_pass_through_transform(kargs.hidden_size)),
                    make_tuple(sequence<0>{}, sequence<1>{}),
                    make_tuple(sequence<0>{}, sequence<1>{}));

                const auto a_window_ = make_tile_window(
                    a_gather_view_,
                    make_tuple(number<BlockShape::Block_M0>{}, number<BlockShape::Block_K0>{}),
                    {0, 0});
                return a_window_;
            }();

            // TODO: gtile using NSub to have less register pressure
            // Note: g_window here inlcude up proj
            // g_ptr = expert_id *
            const auto g_window = [&]() {
                const GDataType* g_ptr = reinterpret_cast<const GDataType*>(kargs.g_ptr) +
                                         static_cast<long_index_t>(expert_id) * expert_stride_0 +
                                         hidden_idx * hidden_size_packed;

                //naive is 4D Tensor [experts, intermediate_idx, KIter, block_n x block_k]
                const auto g_view_ = make_naive_tensor_view<address_space_enum::global>(
                    g_ptr,
                    make_tuple(BlockShape::Block_N0, hidden_size_packed),
                    make_tuple(hidden_size_packed, number<1>{}),
                    number<Pipeline::kAlignmentG>{},
                    number<1>{});
                const auto g_view_1_ = pad_tensor_view(
                    g_view_,
                    make_tuple(number<BlockShape::Block_N0>{}, number<Block_K0_P>{}),
                    sequence<PadIntermediateSize, PadHiddenSize>{});

                const auto g_window_ = make_tile_window(
                    g_view_1_,
                    make_tuple(number<BlockShape::Block_N0>{}, number<Block_K0_P>{}),
                    {0, 0});
                return g_window_;
            }();

            const auto g_scale_window = [&]() {
                const GScaleDataType* g_scale_ptr = reinterpret_cast<const GScaleDataType*>(kargs.g_scale_ptr) +
                                         static_cast<long_index_t>(expert_id) * expert_stride_sc_0 +
                                         hidden_idx * hidden_size_group;

                //naive is 4D Tensor [experts, intermediate_idx, KIter, block_n x block_k]
                const auto g_scale_view_ = make_naive_tensor_view<address_space_enum::global>(
                    g_scale_ptr,
                    make_tuple(BlockShape::Block_N0, hidden_size_group),
                    make_tuple(hidden_size_group, number<1>{}),
                    number<1>{},            // scale alignment
                    number<1>{});

                const auto g_scale_window_ = make_tile_window(
                    g_scale_view_,
                    make_tuple(number<BlockShape::Block_N0>{}, number<Block_K0_Group>{}),
                    {0, 0});
                return g_scale_window_;
            }();

            const auto g_zp_window = [&]() {
                const GZeroPointDataType* g_zp_ptr = (kargs.g_zp_ptr == nullptr)? nullptr :
                                            reinterpret_cast<const GZeroPointDataType*>(kargs.g_zp_ptr) +
                                            static_cast<long_index_t>(expert_id) * expert_stride_zp_0 +
                                            hidden_idx_packed * hidden_size_group;

                //naive is 4D Tensor [experts, intermediate_idx, KIter, block_n x block_k]
                const auto g_zp_view_ = make_naive_tensor_view<address_space_enum::global>(
                    g_zp_ptr,
                    make_tuple(Block_N0_P, hidden_size_group),
                    make_tuple(hidden_size_group, number<1>{}),
                    number<1>{},            // scale alignment
                    number<1>{});

                const auto g_zp_window_ = make_tile_window(
                    g_zp_view_,
                    make_tuple(number<Block_N0_P>{}, number<Block_K0_Group>{}),
                    {0, 0});
                return g_zp_window_;
            }();

            // jump intermediate tile
            const auto d_window = [&]() {
                const DDataType* d_ptr = reinterpret_cast<const DDataType*>(kargs.d_ptr) +
                                         static_cast<long_index_t>(expert_id) * expert_stride_1 +
                                         hidden_idx / Problem::PackFactor;
                // note interm_idx_nr is along the gemm-k dim of 2nd gemm

                const auto d_view_ = make_naive_tensor_view<address_space_enum::global>(
                    d_ptr,
                    make_tuple(kargs.hidden_size, Block_K1_P),
                    make_tuple(intermediate_size_packed, 1),
                    number<Pipeline::kAlignmentD>{},
                    number<1>{});
                const auto d_view_1_ = pad_tensor_view(
                    d_view_,
                    make_tuple(number<BlockShape::Block_N1>{}, number<Block_K1_P>{}),
                    sequence<PadHiddenSize, PadIntermediateSize>{});

                const auto d_window_ = make_tile_window(
                    d_view_1_,
                    make_tuple(number<BlockShape::Block_N1>{}, number<Block_K1_P>{}),
                    {0, 0});
                return d_window_;
            }();

            const auto d_scale_window = [&]() {
                const DScaleDataType* d_scale_ptr = reinterpret_cast<const DScaleDataType*>(kargs.d_scale_ptr) +
                                         static_cast<long_index_t>(expert_id) * expert_stride_sc_1 +
                                         hidden_idx / Problem::QuantBlockSizeK;
                // note interm_idx_nr is along the gemm-k dim of 2nd gemm

                const auto d_scale_view_ = make_naive_tensor_view<address_space_enum::global>(
                    d_scale_ptr,
                    make_tuple(kargs.hidden_size, Block_K1_Group),
                    make_tuple(intermediate_size_group, 1),
                    number<1>{},    // scale alignment
                    number<1>{});

                const auto d_scale_window_ = make_tile_window(
                    d_scale_view_,
                    make_tuple(number<BlockShape::Block_N1>{}, number<Block_K1_Group>{}),
                    {0, 0});
                return d_scale_window_;
            }();

            const auto d_zp_window = [&]() {
                const DZeroPointDataType* d_zp_ptr = (kargs.d_zp_ptr == nullptr) ? nullptr :
                                            reinterpret_cast<const DZeroPointDataType*>(kargs.d_zp_ptr) +
                                            static_cast<long_index_t>(expert_id) * expert_stride_zp_1 +
                                            hidden_idx / Problem::QuantBlockSizeK;
                // note interm_idx_nr is along the gemm-k dim of 2nd gemm

                const auto d_zp_view_ = make_naive_tensor_view<address_space_enum::global>(
                    d_zp_ptr,
                    make_tuple(hidden_size_packed, Block_K1_Group),
                    make_tuple(intermediate_size_group, 1),
                    number<1>{},    // scale alignment
                    number<1>{});

                const auto d_zp_window_ = make_tile_window(
                    d_zp_view_,
                    make_tuple(number<Block_N1_P>{}, number<Block_K1_Group>{}),
                    {0, 0});
                return d_zp_window_;
            }();

            // 2d thread offset, [i_row, i_col] only thread partition index
            const auto o_coord = Pipeline::GetOCoord();
            // FIXME: really ugly.  mmac layout hard code. have to change this for different layout
            // 4 comes from mmac group
            constexpr index_t atomic_issues = BlockShape::Block_M1 / number<4>{};
            statically_indexed_array<TopkWeightDataType, atomic_issues> topk_weights;
            auto o_windows = generate_tuple(
                [&](auto i) {
                    const auto out_sorted_token_id = o_coord[number<0>{}] +
                                                     sorted_tile_id * BlockShape::Block_M0 +
                                                     i * number<4>{};
                    index_t out_token_id = reinterpret_cast<const index_t*>(
                        kargs.sorted_token_ids_ptr)[out_sorted_token_id];
#if CK_TILE_REFERENCE_MOE_SORTING_MOCK_ID
                    out_token_id &= 0xffffff;
#endif
                    topk_weights[i] = reinterpret_cast<const TopkWeightDataType*>(
                        kargs.sorted_weight_ptr)[out_sorted_token_id];

                    auto o_window = [&]() {
                        ODataType* o_ptr = reinterpret_cast<ODataType*>(kargs.o_ptr);
                        auto o_view_     = make_naive_tensor_view<address_space_enum::global,
                                                              memory_operation_enum::atomic_add>(
                            o_ptr,
                            make_tuple(kargs.num_tokens, kargs.hidden_size),
                            make_tuple(kargs.stride_token, 1),
                            number<Pipeline::kAlignmentO>{},
                            number<1>{});

                        // gather is here
                        auto o_scatter_view_ = transform_tensor_view(
                            o_view_,
                            make_tuple(make_indexing_transform(kargs.num_tokens, out_token_id),
                                       make_pass_through_transform(kargs.hidden_size)),
                            make_tuple(sequence<0>{}, sequence<1>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));

                        auto o_window_ = make_tile_window(
                            o_scatter_view_,
                            make_tuple(number<4>{}, number<BlockShape::Block_N1>{}),
                            {0, 0});
                        return o_window_;
                    }();
                    return o_window;
                },
                number<atomic_issues>{});

            // do compute yeah
            Pipeline{}(a_window,
                       g_window,
                       d_window,
                       g_scale_window,
                       d_scale_window,
                       g_zp_window,
                       d_zp_window,
                       o_windows,
                       topk_weights,
                       smem,
                       smem_quant_inter,
                       smem_quant,
                       smem_scale,
                       kargs.hidden_size,
                       kargs.intermediate_size,
                       kargs.g_zp_ptr != nullptr);
            // kargs.stride_token);
        }
    }
};

} // namespace ck_tile
