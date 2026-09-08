#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/gemm.hpp"
#include "ck_tile/ops/elementwise/unary_element_wise_operation.hpp"
#include "ck_tile/ops/fused_moe_2stage/kernel/grouped_moe_gemm_kernel.hpp"
#include "ck_tile/host.hpp"

#include <hip/hip_runtime.h>


namespace ck_tile {


// Maps each per-thread row offset (including SFC traversal) to the sorted token id.
struct MoeStage2IndexAdaptor
{
    const index_t* token_ids = nullptr;
    index_t base_row         = 0;

    CK_TILE_HOST_DEVICE constexpr MoeStage2IndexAdaptor() = default;

    CK_TILE_HOST_DEVICE constexpr MoeStage2IndexAdaptor(const index_t* ids, index_t base)
        : token_ids(ids), base_row(base)
    {
    }

    CK_TILE_DEVICE index_t load_token(const index_t top_index) const
    {
        const index_t row = base_row + top_index;
        constexpr index_t token_mask = (index_t{1} << 24) - 1;
        index_t token_id             = token_ids[row] & token_mask;
        return token_id;
    }

    template <typename LowIdx, typename UpIdx>
    CK_TILE_DEVICE void calculate_lower_index(LowIdx& idx_low, const UpIdx& idx_up) const
    {
        idx_low(number<0>{}) = load_token(idx_up[number<0>{}]);
    }

    template <typename LowDiff, typename UpDiff, typename LowIdx, typename UpIdx>
    CK_TILE_DEVICE void update_lower_index(LowDiff& idx_diff_low,
                                           const UpDiff& idx_diff_up,
                                           LowIdx& idx_low,
                                           const UpIdx& idx_up) const
    {
        const index_t next_up     = idx_up[number<0>{}] + idx_diff_up[number<0>{}];
        const index_t next_token  = load_token(next_up);
        idx_diff_low(number<0>{}) = next_token - idx_low(number<0>{});
        idx_low(number<0>{})      = next_token;
    }

    CK_TILE_HOST_DEVICE static constexpr bool is_known_at_compile_time() { return false; }
};


struct FusedMoeStage1HostArgs
{
    const void* a_ptr;                 // [m, k], input token
    const void* a_scale_ptr;           // [m, 1], token scale
    const void* g_ptr;                 // [e, 2*n, k]
    const void* g_scale_ptr;           // [e, 1, n], gate(up) scale
    const void* g_zp_ptr;              // [e, 2*n, k/group], gate(up) zero-point
    const void* local_expert_mask_ptr; // [e], local_expert_mask_ptr for EP
    void* o_ptr;                       // [m, topk, 2*n]

    void* sorted_token_ids_ptr;  // [max_num_tokens_padded]
    void* sorted_weight_ptr;     // [max_num_tokens_padded], should multiply topk_weight if it is not nullptr
    void* sorted_expert_ids_ptr; // [(max_num_tokens_padded + block_size - 1) / block_size]
    void* tokens_positions_per_expert_ptr;     // [num_experts*2], represents number of tokens and positions assigned to each expert
    void* num_sorted_tiles_ptr;  // [1]

    // void* tmp_out;              // tempary output

    ck_tile::index_t block_m;           // block_m, used to devide the input
    ck_tile::index_t hidden_size;       // k
    ck_tile::index_t intermediate_size; // n / TP, for Gate. and Up, Down is also this value
    ck_tile::index_t num_tokens;        // input number of tokens for current iteration
    ck_tile::index_t num_experts;       // number of groups
    ck_tile::index_t topk;              // need this?

    ck_tile::index_t stride_token;      // for input, stride for each row, should >= hidden_size
    
    ck_tile::index_t block_shape_n;     // quant block n size
    ck_tile::index_t block_shape_k;     // quant block k size

    const ck_tile::index_t* block_start_ptr = nullptr; // device pointer to per-expert block range start
    const ck_tile::index_t* block_end_ptr   = nullptr; // device pointer to per-expert block range end
    const ck_tile::index_t* pre_tokens_ptr  = nullptr;
};


struct FusedMoeStage2HostArgs
{
    const void* a_ptr;                 // [m, k], input token
    const void* a_scale_ptr;           // [m, 1], token scale
    const void* g_ptr;                 // [e, 2*n, k]
    const void* g_scale_ptr;           // [e, 1, n], gate(up) scale
    const void* g_zp_ptr;              // [e, 2*n, k/group], gate(up) zero-point
    const void* local_expert_mask_ptr; // [e], local_expert_mask_ptr for EP
    void* o_ptr;                       // [m, topk, 2*n]

    void* sorted_token_ids_ptr;  // [max_num_tokens_padded]
    void* sorted_weight_ptr;     // [max_num_tokens_padded], should multiply topk_weight if it is not nullptr
    void* sorted_expert_ids_ptr; // [(max_num_tokens_padded + block_size - 1) / block_size]
    void* tokens_positions_per_expert_ptr;     // [num_experts*2], represents number of tokens and positions assigned to each expert
    void* num_sorted_tiles_ptr;  // [1]

    // void* tmp_out;              // tempary output

    ck_tile::index_t block_m;           // block_m, used to devide the input
    ck_tile::index_t hidden_size;       // k
    ck_tile::index_t intermediate_size; // n / TP, for Gate. and Up, Down is also this value
    ck_tile::index_t num_tokens;        // input number of tokens for current iteration
    ck_tile::index_t num_experts;       // number of groups
    ck_tile::index_t topk;              // need this?

    ck_tile::index_t stride_token;      // for output, stride for each row, should >= hidden_size
    
    ck_tile::index_t block_shape_n;     // quant block n size
    ck_tile::index_t block_shape_k;     // quant block k size

    const ck_tile::index_t* block_start_ptr = nullptr; // device pointer to per-expert block range start
    const ck_tile::index_t* block_end_ptr   = nullptr; // device pointer to per-expert block range end
    const ck_tile::index_t* pre_tokens_ptr  = nullptr;
};


template <typename TilePartitioner_, typename GemmPipeline_, typename EpiloguePipeline_>
struct FusedMoeStage1Kernel : public GroupedMoeGemmKernel<TilePartitioner_, GemmPipeline_, EpiloguePipeline_>
{
    // using Base = GroupedMoeGemmKernel<TilePartitioner_, GemmPipeline_, EpiloguePipeline_>;
    using BaseUniGemmKernel = UniversalMoeGemmKernel<TilePartitioner_, GemmPipeline_, EpiloguePipeline_>;
    
    using TilePartitioner  = remove_cvref_t<TilePartitioner_>;
    using GemmPipeline     = remove_cvref_t<GemmPipeline_>;
    using EpiloguePipeline = remove_cvref_t<EpiloguePipeline_>;

    using ADataType = remove_cvref_t<typename GemmPipeline::ADataType>;
    using BDataType = remove_cvref_t<typename GemmPipeline::BDataType>;
    using CDataType = remove_cvref_t<typename EpiloguePipeline::ODataType>;
    using AScaleDataType = remove_cvref_t<typename GemmPipeline::AScaleDataType>;
    using BScaleDataType = remove_cvref_t<typename GemmPipeline::BScaleDataType>;

    using TopkWeightDataType = float;   // assume topk weight is float


    // using SplitKBatchOffset = remove_cvref_t<typename BaseUniGemmKernel::SplitKBatchOffset>;

    using OffsetTile1DPartitioner = OffsettedTile1DPartitioner<TilePartitioner>;

    static constexpr bool UsePersistentKernel = GemmPipeline::UsePersistentKernel;

    static constexpr auto I0 = number<0>();
    static constexpr auto I1 = number<1>();
    static constexpr auto I2 = number<2>();
    static constexpr auto I3 = number<3>();
    static constexpr auto I4 = number<4>();


    struct FusedMoeStage1KernelArgs
    {
        const void* a_ptr;                 // [m, k], input token
        const void* a_scale_ptr;           // [m, 1], token scale
        const void* g_ptr;                 // [e, 2*n, k]
        const void* g_scale_ptr;           // [e, 1, n], gate(up) scale
        const void* g_zp_ptr;              // [e, 2*n, k/group], gate(up) zero-point
        const void* local_expert_mask_ptr; // [e], local_expert_mask_ptr for EP
        void* o_ptr;                       // [m, topk, 2*n]

        void* sorted_token_ids_ptr;  // [max_num_tokens_padded]
        void* sorted_weight_ptr;     // [max_num_tokens_padded]
        void* sorted_expert_ids_ptr; // [(max_num_tokens_padded + block_size - 1) / block_size]
        void* tokens_positions_per_expert_ptr;     // [num_experts*2], represents number of tokens and positions assigned to each expert
        void* num_sorted_tiles_ptr;  // [1]

        // void* tmp_out;              // tempary output

        ck_tile::index_t block_m;           // block_m, used to devide the input
        ck_tile::index_t hidden_size;       // k
        ck_tile::index_t intermediate_size; // n / TP, for Gate. and Up, Down is also this value
        ck_tile::index_t num_tokens;        // input number of tokens for current iteration
        ck_tile::index_t num_experts;       // number of groups
        ck_tile::index_t topk;              // need this?

        ck_tile::index_t stride_token;      // for input, stride for each row, should >= hidden_size
        
        ck_tile::index_t block_shape_n;     // quant block n size
        ck_tile::index_t block_shape_k;     // quant block k size

        const ck_tile::index_t* block_start_ptr;
        const ck_tile::index_t* block_end_ptr;
        const ck_tile::index_t* pre_tokens_ptr;
    };

    using Kargs = FusedMoeStage1KernelArgs;
    using Hargs = FusedMoeStage1HostArgs;

    CK_TILE_HOST static constexpr Kargs MakeKargs(const Hargs& hargs)
    {
        // TODO: hargs/kargs not guranteed to be the same
        return bit_cast<Kargs>(hargs);
    }

    [[nodiscard]] CK_TILE_HOST static const std::string GetName()
    {
        // clang-format off
        using P_ = GemmPipeline;

        return concat('_', "moe_stage1", gemm_prec_str<ADataType, BDataType>(),
                      concat('x', P_::MPerBlock, P_::NPerBlock, P_::KPerBlock),
                      concat('x', P_::GetVectorSizeA(), P_::GetVectorSizeB(), P_::GetVectorSizeC()),
                      concat('x', P_::kPadM, P_::kPadN, P_::kPadK),
                      (UsePersistentKernel ? "Persistent" : "NonPersistent"));
        // clang-format on
    }

    CK_TILE_DEVICE static void
    RunMoeGemm1WithPipelineSelection2LDS(const ADataType* a_ptr,
                                        const BDataType* b_ptr,
                                        CDataType* c_ptr,
                                        void* __restrict__ smem_ptr_0,
                                        void* __restrict__ smem_ptr_1,
                                        const UniversalMoeGemmKernelArgs<>& kargs,
                                        const index_t block_idx_m,
                                        const index_t block_idx_n,
                                        const index_t moe_num_tokens,
                                        const index_t moe_token_id,
                                        const index_t a_scale_token_id,
                                        const void* sorted_weight_ptr,
                                        const index_t sorted_row_start)
    {
        std::array<const AScaleDataType*, BaseUniGemmKernel::NumATensor> as_scale_ptr
            [[maybe_unused]]{};
        std::array<const BScaleDataType*, BaseUniGemmKernel::NumBTensor> bs_scale_ptr
            [[maybe_unused]]{};
        if constexpr(GemmPipeline::UseABScale)
        {
            static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                constexpr int idx = decltype(i)::value;
                as_scale_ptr[i] = static_cast<const AScaleDataType*>(kargs.a_scale_ptr[i]);
            });

            static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                constexpr int idx = decltype(i)::value;
                bs_scale_ptr[i] = static_cast<const BScaleDataType*>(kargs.b_scale_ptr[i]);
            });
        }

        // Create Gemm tensor views, pad views and tile windows
        const auto& gemm_tensor_views_tuple =
            BaseUniGemmKernel::template MakeMoeGemm1TensorViews<EpiloguePipeline::MemoryOperation>(
                {a_ptr},
                {b_ptr},
                c_ptr,
                kargs,
                moe_num_tokens,
                as_scale_ptr,
                bs_scale_ptr);

        const auto& gemm_pad_views = BaseUniGemmKernel::MakeGemmPadViews(gemm_tensor_views_tuple);

        auto gemm_tile_windows =
            BaseUniGemmKernel::MakeMoeGemm1TileWindows(gemm_pad_views, block_idx_m, block_idx_n, moe_token_id, a_scale_token_id);
        const auto& a_block_window = gemm_tile_windows.at(I0);
        const auto& b_block_window = gemm_tile_windows.at(I1);

        // Get hot-loop and tail configuration
        const index_t num_loop = __builtin_amdgcn_readfirstlane(
            TilePartitioner::GetLoopNum(kargs.K));
        const TailNumber tail_num = GemmPipeline::GetBlockLoopTailNum(num_loop);

        // Run GEMM pipeline with compile-time branching
        const auto& c_block_tile = [&]() {
            if constexpr(GemmPipeline::Preshuffle)
            {
                static_assert(false, "RunGemmWithPipelineSelection2LDS Not check!");

                if constexpr(GemmPipeline::UseABScale)
                {
                    const auto& a_scale_block_window = gemm_tile_windows.at(I3);
                    const auto& b_scale_block_window = gemm_tile_windows.at(I4);

                    // Preshuffle version - without has_hot_loop parameter
                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1,
                                                              a_scale_block_window[I0],
                                                              b_scale_block_window[I0]);
                }
                else
                {
                    // Preshuffle version - without has_hot_loop parameter
                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1);
                }
            }
            else
            {
                // Regular version - with has_hot_loop parameter
                const bool has_hot_loop = GemmPipeline::BlockHasHotloop(num_loop);

                if constexpr(GemmPipeline::UseABScale)
                {
                    const auto& a_scale_block_window = gemm_tile_windows.at(I3);
                    const auto& b_scale_block_window = gemm_tile_windows.at(I4);

                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              has_hot_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1,
                                                              a_scale_block_window[I0],
                                                              b_scale_block_window[I0]);
                }
                else
                {
                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              has_hot_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1);
                }
            }
        }();

        if (sorted_weight_ptr != nullptr) {

            auto* scale_m_ptr = reinterpret_cast<const TopkWeightDataType*>(sorted_weight_ptr) + sorted_row_start;
            constexpr auto scale_lengths = make_tuple(number<EpiloguePipeline::MPerIteration>{},
                                                      number<EpiloguePipeline::NPerIteration>{});
            constexpr auto scale_strides = make_tuple(number<1>{}, number<0>{});    // 0 means the scale will be broadcasted along this dim
            auto scale_desc = make_naive_tensor_descriptor(scale_lengths, scale_strides);
            auto scale_m_view =
                make_tensor_view<address_space_enum::global>(const_cast<TopkWeightDataType*>(scale_m_ptr), scale_desc);


            // Run Epilogue Pipeline
            auto& c_block_window = gemm_tile_windows.at(I2);
            EpiloguePipeline{}.template
            operator()<decltype(c_block_window), decltype(c_block_tile), decltype(tuple<>{})>(
                c_block_window, c_block_tile, tuple<>{}, smem_ptr_0, scale_m_view);

        } else {

            // Run Epilogue Pipeline
            auto& c_block_window = gemm_tile_windows.at(I2);
            EpiloguePipeline{}.template
            operator()<decltype(c_block_window), decltype(c_block_tile), decltype(tuple<>{})>(
                c_block_window, c_block_tile, tuple<>{}, smem_ptr_0);
        }
        
    }


    CK_TILE_DEVICE static void
    RunMoeGemm1DualPass(const ADataType* a_ptr,
                        const BDataType* gate_b_ptr,
                        const BDataType* up_b_ptr,
                        CDataType* c_ptr,
                        void* __restrict__ smem_ptr_0,
                        void* __restrict__ smem_ptr_1,
                        const UniversalMoeGemmKernelArgs<>& gate_kargs,
                        const BScaleDataType* up_b_scale_ptr,
                        const index_t block_idx_m,
                        const index_t block_idx_n,
                        const index_t moe_num_tokens,
                        const index_t moe_token_id,
                        const index_t a_scale_token_id,
                        const void* sorted_weight_ptr,
                        const index_t sorted_row_start)
    {
        const auto launch_pipeline = [&](const auto& gemm_tile_windows,
                                         const auto& pass_kargs,
                                         auto* pass_smem0,
                                         auto* pass_smem1) {
            const auto& a_block_window = gemm_tile_windows.at(I0);
            const auto& b_block_window = gemm_tile_windows.at(I1);

            const index_t num_loop =
                __builtin_amdgcn_readfirstlane(TilePartitioner::GetLoopNum(pass_kargs.K));
            const TailNumber tail_num = GemmPipeline::GetBlockLoopTailNum(num_loop);
            const bool has_hot_loop   = GemmPipeline::BlockHasHotloop(num_loop);

            if constexpr(GemmPipeline::Preshuffle)
            {
                static_assert(false, "RunMoeGemm1DualPass preshuffle path not implemented");
            }
            else
            {
                if constexpr(GemmPipeline::UseABScale)
                {
                    const auto& a_scale_block_window = gemm_tile_windows.at(I3);
                    const auto& b_scale_block_window = gemm_tile_windows.at(I4);

                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              has_hot_loop,
                                                              tail_num,
                                                              pass_smem0,
                                                              pass_smem1,
                                                              a_scale_block_window[I0],
                                                              b_scale_block_window[I0]);
                }
                else
                {
                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              has_hot_loop,
                                                              tail_num,
                                                              pass_smem0,
                                                              pass_smem1);
                }
            }
        };

        std::array<const AScaleDataType*, BaseUniGemmKernel::NumATensor> gate_up_as_scale_ptr
            [[maybe_unused]]{};
        std::array<const BScaleDataType*, BaseUniGemmKernel::NumBTensor> gate_bs_scale_ptr
            [[maybe_unused]]{};
        std::array<const BScaleDataType*, BaseUniGemmKernel::NumBTensor> up_bs_scale_ptr
            [[maybe_unused]]{};

        if constexpr(GemmPipeline::UseABScale)
        {
            static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                gate_up_as_scale_ptr[i] = static_cast<const AScaleDataType*>(gate_kargs.a_scale_ptr[i]);
            });

            static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                gate_bs_scale_ptr[i] =
                    static_cast<const BScaleDataType*>(gate_kargs.b_scale_ptr[i]);
                up_bs_scale_ptr[i] =
                    static_cast<const BScaleDataType*>(up_b_scale_ptr);
            });
        }

        const auto gate_views =
            BaseUniGemmKernel::template MakeMoeGemm1TensorViews<EpiloguePipeline::MemoryOperation>(
                {a_ptr},
                {gate_b_ptr},
                c_ptr,
                gate_kargs,
                moe_num_tokens,
                gate_up_as_scale_ptr,
                gate_bs_scale_ptr);
        const auto gate_pad_views = BaseUniGemmKernel::MakeGemmPadViews(gate_views);
        auto gate_tile_windows    = BaseUniGemmKernel::MakeMoeGemm1TileWindows(
            gate_pad_views, block_idx_m, block_idx_n, moe_token_id, a_scale_token_id);

        const auto gate_block_tile =
            launch_pipeline(gate_tile_windows, gate_kargs, smem_ptr_0, smem_ptr_1);

    
        // Up pass.
        // up_kargs中只有bs_ptr与b_scale_ptr与gate_kargs不同，而MakeMoeGemm1TensorViews及
        // launch_pipeline中未使用up_kargs中的这两个地址，故可复用gate_kargs
        auto up_kargs = gate_kargs;

        const auto up_views =
            BaseUniGemmKernel::template MakeMoeGemm1TensorViews<EpiloguePipeline::MemoryOperation>(
                {a_ptr},
                {up_b_ptr},
                c_ptr,
                up_kargs,
                moe_num_tokens,
                gate_up_as_scale_ptr,
                up_bs_scale_ptr);
        const auto up_pad_views = BaseUniGemmKernel::MakeGemmPadViews(up_views);
        auto up_tile_windows    = BaseUniGemmKernel::MakeMoeGemm1TileWindows(
            up_pad_views, block_idx_m, block_idx_n, moe_token_id, a_scale_token_id);

        const auto up_block_tile =
            launch_pipeline(up_tile_windows, up_kargs, smem_ptr_0, smem_ptr_1);

        auto silu_gate_tile = gate_block_tile;
        tile_elementwise_inout(element_wise::Silu{}, silu_gate_tile, gate_block_tile);

        auto fused_tile = up_block_tile;
        tile_elementwise_inout(
            element_wise::MultiDMultiply{}, fused_tile, fused_tile, silu_gate_tile);

        
        // Run Epilogue Pipeline
        auto emit_result = [&](auto& tile_windows) {
            if(sorted_weight_ptr != nullptr)
            {
                auto* scale_m_ptr = reinterpret_cast<const TopkWeightDataType*>(sorted_weight_ptr) +
                                    sorted_row_start;
                constexpr auto scale_lengths =
                    make_tuple(number<EpiloguePipeline::MPerIteration>{},
                               number<EpiloguePipeline::NPerIteration>{});
                constexpr auto scale_strides =
                    make_tuple(number<1>{}, number<0>{});
                auto scale_desc = make_naive_tensor_descriptor(scale_lengths, scale_strides);
                auto scale_m_view = make_tensor_view<address_space_enum::global>(
                    const_cast<TopkWeightDataType*>(scale_m_ptr), scale_desc);

                auto& c_block_window = tile_windows.at(I2);
                EpiloguePipeline{}.template
                    operator()<decltype(c_block_window), decltype(fused_tile), decltype(tuple<>{})>(
                        c_block_window, fused_tile, tuple<>{}, smem_ptr_0, scale_m_view);
            }
            else
            {
                auto& c_block_window = tile_windows.at(I2);
                EpiloguePipeline{}.template
                    operator()<decltype(c_block_window), decltype(fused_tile), decltype(tuple<>{})>(
                        c_block_window, fused_tile, tuple<>{}, smem_ptr_0);
            }
        };

        emit_result(gate_tile_windows);
    }

    CK_TILE_HOST_DEVICE static constexpr auto GetSmemSize() -> index_t
    {
        return max(GemmPipeline::GetSmemSize(), EpiloguePipeline::GetSmemSize());
    }

    CK_TILE_DEVICE void Run(const UniversalMoeGemmKernelArgs<>& gate_kargs,
                            const BDataType* up_b_ptr,
                            const BScaleDataType* up_b_scale_ptr, 
                            const tuple<index_t, index_t>& block_idx_2d,
                            const index_t moe_num_tokens,
                            const index_t moe_token_id,
                            const index_t a_scale_token_id,
                            const void* sorted_weight_ptr,
                            const index_t sorted_row_start) const
    {

        static_assert(GemmPipeline::DoubleSmemBuffer || !GemmPipeline::Preshuffle,
                      "SingleSmemBuffer and Preshuffle cannot both be enabled simultaneously!");

        const auto [iM, iN] = block_idx_2d;

        const index_t i_m = __builtin_amdgcn_readfirstlane(iM * TilePartitioner::MPerBlock);
        const index_t i_n = __builtin_amdgcn_readfirstlane(iN * TilePartitioner::NPerBlock);

        const ADataType* a_ptr = static_cast<const ADataType*>(gate_kargs.as_ptr[0]);
        const BDataType* gate_b_ptr = static_cast<const BDataType*>(gate_kargs.bs_ptr[0]);
        CDataType* c_ptr = static_cast<CDataType*>(gate_kargs.e_ptr);

        // allocate LDS
        __shared__ char smem_ptr_0[GetSmemSize()];

        if constexpr(GemmPipeline::DoubleSmemBuffer == true)
        {

            __shared__ char smem_ptr_1[GetSmemSize()];

            RunMoeGemm1DualPass(a_ptr,
                                gate_b_ptr,
                                up_b_ptr,
                                c_ptr,
                                smem_ptr_0,
                                smem_ptr_1,
                                gate_kargs,
                                up_b_scale_ptr,
                                i_m,
                                i_n,
                                moe_num_tokens,
                                moe_token_id,
                                a_scale_token_id,
                                sorted_weight_ptr,
                                sorted_row_start);

        }
        else // SingleSmemBuffer
        {
            static_assert(false, "SingleSmemBuffer Not support!");
        }
    }

    CK_TILE_DEVICE index_t FindGroupId(Kargs& kargs,
                                       index_t block_id,
                                       index_t group_count) const
    {
        index_t left     = 0;
        index_t right    = group_count;
        index_t group_id = index_t((left + right) >> 1);

        while((!(block_id >= kargs.block_start_ptr[group_id] &&
                 block_id < kargs.block_end_ptr[group_id])) &&
              left <= right)
        {
            if(block_id < kargs.block_start_ptr[group_id])
            {
                right = group_id;
            }
            else
            {
                left = group_id;
            }
            group_id = index_t((left + right) >> 1);
        }

        return group_id;
    }
    
    // For non-persistent kernels
    template <bool U = UsePersistentKernel, typename = std::enable_if_t<!U>>
    CK_TILE_DEVICE void operator()(Kargs kargs, const index_t group_count) const
    {
        _Pragma("clang diagnostic push")
        _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");

        index_t num_sorted_tiles = __builtin_amdgcn_readfirstlane(
                *reinterpret_cast<const index_t*>(kargs.num_sorted_tiles_ptr));
        num_sorted_tiles = num_sorted_tiles / kargs.block_m;

        constexpr index_t token_mask = (index_t{1} << 24) - 1;

        // get expert start offset
        const auto a_coord = GemmPipeline::GetACoord(); // 2d thread offset, [i_row, i_col]
        const auto a_scale_coord = GemmPipeline::GetAScaleCoord();

        const int gemm_N_half  = kargs.intermediate_size;
        const int gemm_N_total = gemm_N_half * 2;
        const int gemm_K       = kargs.hidden_size;

        [[maybe_unused]] index_t block_shape_k = 1;
        [[maybe_unused]] index_t block_shape_n = 1;
        [[maybe_unused]] index_t k_blocks      = 1;
        [[maybe_unused]] index_t gate_stride_a_scales = 0;
        [[maybe_unused]] const AScaleDataType* a_scale_base = nullptr;

        if constexpr(GemmPipeline::UseABScale)
        {
            block_shape_k = kargs.block_shape_k > 0 ? kargs.block_shape_k : static_cast<index_t>(1);
            block_shape_n = kargs.block_shape_n > 0 ? kargs.block_shape_n : static_cast<index_t>(1);
            k_blocks      = ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_K), block_shape_k);
            gate_stride_a_scales = k_blocks;
            a_scale_base = static_cast<const AScaleDataType*>(kargs.a_scale_ptr);
        }


        const index_t block_id   = ck_tile::get_block_1d_id();
        const index_t group_id = FindGroupId(kargs, block_id, group_count);

        
        // group_count = num_experts
        const index_t expert_start = __builtin_amdgcn_readfirstlane(
            reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id + group_count]);
        const int tokens_num = __builtin_amdgcn_readfirstlane(
            reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id]);
        const int pre_token_num = __builtin_amdgcn_readfirstlane(
            reinterpret_cast<const index_t*>(kargs.pre_tokens_ptr)[group_id]);
        if (tokens_num <= 0) {
            return;
        }

        const int gemm_M = tokens_num;

        const BDataType* g_expert_ptr_gate = reinterpret_cast<const BDataType*>(kargs.g_ptr) +
            static_cast<long_index_t>(group_id) * gemm_N_total * kargs.stride_token;

        //单独传递指针，不重复构建UniversalMoeGemmKernelArgs，减少sgpr占用
        const BDataType* g_expert_ptr_up = g_expert_ptr_gate + static_cast<long_index_t>(gemm_N_half) * kargs.stride_token;
        const BScaleDataType* g_expert_scale_ptr_up = nullptr;

        CDataType* o_expert_ptr = reinterpret_cast<CDataType*>(kargs.o_ptr) + static_cast<long_index_t>(pre_token_num) * gemm_N_half;


        auto gate_gemm_arg =
            UniversalMoeGemmKernelArgs<>{{type_convert<const ADataType*>(kargs.a_ptr)},
                                            {g_expert_ptr_gate},
                                            o_expert_ptr,
                                            gemm_M,
                                            gemm_N_half,
                                            gemm_K,
                                            {kargs.stride_token},
                                            {kargs.stride_token},
                                            gemm_N_half};

        if constexpr(GemmPipeline::UseABScale)
        {
            const auto* b_scale_base = static_cast<const BScaleDataType*>(kargs.g_scale_ptr);
            std::array<const void*, BaseUniGemmKernel::NumBTensor> gate_b_scale_ptrs{};
            std::array<const void*, BaseUniGemmKernel::NumBTensor> up_b_scale_ptrs{};
            std::array<index_t, BaseUniGemmKernel::NumBTensor> stride_b_scales{};
            std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_k{};
            std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_n{};
            const index_t gate_stride_b_scales = k_blocks;

            const index_t n_blocks_total =
                ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_N_total), block_shape_n);
            const index_t n_blocks_half =
                ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_N_half), block_shape_n);
            const auto gate_b_scale_offset =
                static_cast<long_index_t>(group_id) * n_blocks_total * k_blocks;
            const auto up_b_scale_offset = gate_b_scale_offset + static_cast<long_index_t>(n_blocks_half) * k_blocks;

            //单独传递指针，不重复构建UniversalMoeGemmKernelArgs，减少sgpr占用
            g_expert_scale_ptr_up = b_scale_base + up_b_scale_offset;

            static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                gate_b_scale_ptrs[i] = b_scale_base + gate_b_scale_offset;
                stride_b_scales[i]   = gate_stride_b_scales;
                b_scale_block_k[i]   = block_shape_k;
                b_scale_block_n[i]   = block_shape_n;
            });

            gate_gemm_arg.b_scale_ptr     = gate_b_scale_ptrs;
            gate_gemm_arg.stride_B_scales = stride_b_scales;
            gate_gemm_arg.b_scale_k_block_lengths = b_scale_block_k;
            gate_gemm_arg.b_scale_n_block_lengths = b_scale_block_n;
        }

        index_t cum_grid_size = TilePartitioner::GridSize(gemm_M, gemm_N_half);

        const auto block_idx_2d = OffsetTile1DPartitioner::GetOffsetedTileIndex(
            0, gemm_M, gemm_N_half, block_id % cum_grid_size);

        // get token_id according to block_idx_2d
        // MPerBlock需与moe sorting中的block_m保持一致，否则最后的block可能取到<sorted_token_ids_ptr>越界的token_id，
        // 因group gemm中tile_distribution是按MPerBlock划分的
        const auto [iM, iN] = block_idx_2d;
        const index_t i_m = __builtin_amdgcn_readfirstlane(iM * TilePartitioner::MPerBlock);
        const index_t sorted_row_start = expert_start + i_m;
        const auto sorted_in_token_id = a_coord[number<0>{}] + sorted_row_start;
        index_t input_token_id = reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr)[sorted_in_token_id];
        input_token_id &= token_mask;


        index_t a_scale_token_id = 0;
        if constexpr(GemmPipeline::UseABScale)
        {
            const auto sorted_in_token_id = a_scale_coord[number<0>{}] + sorted_row_start;
            a_scale_token_id = reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr)[sorted_in_token_id];
            a_scale_token_id &= token_mask;
        }

        // get input_token_id according to block_idx_2d
        auto gate_kargs = gate_gemm_arg;

        if constexpr(GemmPipeline::UseABScale)
        {
            std::array<const void*, BaseUniGemmKernel::NumATensor> gate_a_scale_ptrs{};
            std::array<index_t, BaseUniGemmKernel::NumATensor> stride_a_scales{};
            std::array<index_t, BaseUniGemmKernel::NumATensor> a_scale_block_k{};

            static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                gate_a_scale_ptrs[i] = a_scale_base;
                stride_a_scales[i]   = gate_stride_a_scales;
                a_scale_block_k[i]   = block_shape_k;
            });

            gate_gemm_arg.a_scale_ptr     = gate_a_scale_ptrs;
            gate_gemm_arg.stride_A_scales = stride_a_scales;
            gate_gemm_arg.a_scale_k_block_lengths = a_scale_block_k;
        }

        Run(gate_gemm_arg,
            g_expert_ptr_up,
            g_expert_scale_ptr_up,
            block_idx_2d,
            kargs.num_tokens,
            input_token_id,
            a_scale_token_id,
            kargs.sorted_weight_ptr,
            sorted_row_start);
    

    }


    // For persistent kernels
    template <bool U   = UsePersistentKernel,
              typename = std::enable_if_t<U>,
              typename = void> // extra template parameter to avoid redefinition
    CK_TILE_DEVICE void operator()(Kargs kargs, const index_t group_count) const
    {

        _Pragma("clang diagnostic push")
        _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");

        const index_t grid_size  = ck_tile::get_grid_size();

        index_t num_sorted_tiles = __builtin_amdgcn_readfirstlane(
                *reinterpret_cast<const index_t*>(kargs.num_sorted_tiles_ptr));
        num_sorted_tiles = num_sorted_tiles / kargs.block_m;

        int pre_token_num = 0;
        constexpr index_t token_mask = (index_t{1} << 24) - 1;

        // get expert start offset
        const auto a_coord = GemmPipeline::GetACoord(); // 2d thread offset, [i_row, i_col]
        const auto a_scale_coord = GemmPipeline::GetAScaleCoord();

        const int gemm_N_half  = kargs.intermediate_size;
        const int gemm_N_total = gemm_N_half * 2;
        const int gemm_K       = kargs.hidden_size;

        [[maybe_unused]] index_t block_shape_k = 1;
        [[maybe_unused]] index_t block_shape_n = 1;
        [[maybe_unused]] index_t k_blocks      = 1;
        [[maybe_unused]] index_t gate_stride_a_scales = 0;
        [[maybe_unused]] const AScaleDataType* a_scale_base = nullptr;

        if constexpr(GemmPipeline::UseABScale)
        {
            block_shape_k = kargs.block_shape_k > 0 ? kargs.block_shape_k : static_cast<index_t>(1);
            block_shape_n = kargs.block_shape_n > 0 ? kargs.block_shape_n : static_cast<index_t>(1);
            k_blocks      = ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_K), block_shape_k);
            gate_stride_a_scales = k_blocks;
            a_scale_base = static_cast<const AScaleDataType*>(kargs.a_scale_ptr);
        }

        for(index_t group_id = 0; group_id < group_count; ++group_id)
        {
            // group_count = num_experts
            const index_t expert_start = __builtin_amdgcn_readfirstlane(
                reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id + group_count]);
            const int tokens_num = __builtin_amdgcn_readfirstlane(
                reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id]);
            if (tokens_num <= 0) {
                continue;
            }

            const int gemm_M = tokens_num;

            const BDataType* g_expert_ptr_gate = reinterpret_cast<const BDataType*>(kargs.g_ptr) +
                static_cast<long_index_t>(group_id) * gemm_N_total * kargs.stride_token;

            //单独传递指针，不重复构建UniversalMoeGemmKernelArgs，减少sgpr占用
            const BDataType* g_expert_ptr_up = g_expert_ptr_gate + static_cast<long_index_t>(gemm_N_half) * kargs.stride_token;
            const BScaleDataType* g_expert_scale_ptr_up = nullptr;

            CDataType* o_expert_ptr = reinterpret_cast<CDataType*>(kargs.o_ptr) +
                static_cast<long_index_t>(pre_token_num) * gemm_N_half;

            pre_token_num += tokens_num;

            auto gate_gemm_arg =
                UniversalMoeGemmKernelArgs<>{{type_convert<const ADataType*>(kargs.a_ptr)},
                                              {g_expert_ptr_gate},
                                              o_expert_ptr,
                                              gemm_M,
                                              gemm_N_half,
                                              gemm_K,
                                              {kargs.stride_token},
                                              {kargs.stride_token},
                                              gemm_N_half};

            if constexpr(GemmPipeline::UseABScale)
            {
                const auto* b_scale_base = static_cast<const BScaleDataType*>(kargs.g_scale_ptr);
                std::array<const void*, BaseUniGemmKernel::NumBTensor> gate_b_scale_ptrs{};
                std::array<const void*, BaseUniGemmKernel::NumBTensor> up_b_scale_ptrs{};
                std::array<index_t, BaseUniGemmKernel::NumBTensor> stride_b_scales{};
                std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_k{};
                std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_n{};
                const index_t gate_stride_b_scales = k_blocks;

                const index_t n_blocks_total =
                    ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_N_total), block_shape_n);
                const index_t n_blocks_half =
                    ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_N_half), block_shape_n);
                const auto gate_b_scale_offset =
                    static_cast<long_index_t>(group_id) * n_blocks_total * k_blocks;
                const auto up_b_scale_offset = gate_b_scale_offset +
                                               static_cast<long_index_t>(n_blocks_half) *
                                                   k_blocks;

                //单独传递指针，不重复构建UniversalMoeGemmKernelArgs，减少sgpr占用
                g_expert_scale_ptr_up = b_scale_base + up_b_scale_offset;

                static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                    gate_b_scale_ptrs[i] = b_scale_base + gate_b_scale_offset;
                    stride_b_scales[i]   = gate_stride_b_scales;
                    b_scale_block_k[i]   = block_shape_k;
                    b_scale_block_n[i]   = block_shape_n;
                });

                gate_gemm_arg.b_scale_ptr     = gate_b_scale_ptrs;
                gate_gemm_arg.stride_B_scales = stride_b_scales;
                gate_gemm_arg.b_scale_k_block_lengths = b_scale_block_k;
                gate_gemm_arg.b_scale_n_block_lengths = b_scale_block_n;
            }

            index_t block_id = ck_tile::get_block_1d_id();
            index_t cum_grid_size = TilePartitioner::GridSize(gemm_M, gemm_N_half);

            while(block_id < cum_grid_size)
            {
                const auto block_idx_2d = OffsetTile1DPartitioner::GetOffsetedTileIndex(
                    0, gemm_M, gemm_N_half, block_id % cum_grid_size);

                // get token_id according to block_idx_2d
                // MPerBlock需与moe sorting中的block_m保持一致，否则最后的block可能取到<sorted_token_ids_ptr>越界的token_id，
                // 因group gemm中tile_distribution是按MPerBlock划分的
                const auto [iM, iN] = block_idx_2d;
                const index_t i_m = __builtin_amdgcn_readfirstlane(iM * TilePartitioner::MPerBlock);
                const index_t sorted_row_start = expert_start + i_m;
                const auto sorted_in_token_id = a_coord[number<0>{}] + sorted_row_start;
                index_t input_token_id = reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr)[sorted_in_token_id];
                input_token_id &= token_mask;


                index_t a_scale_token_id = 0;
                if constexpr(GemmPipeline::UseABScale)
                {
                    const auto sorted_in_token_id = a_scale_coord[number<0>{}] + sorted_row_start;
                    a_scale_token_id = reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr)[sorted_in_token_id];
                    a_scale_token_id &= token_mask;
                }

                // get input_token_id according to block_idx_2d
                auto gate_kargs = gate_gemm_arg;

                if constexpr(GemmPipeline::UseABScale)
                {
                    std::array<const void*, BaseUniGemmKernel::NumATensor> gate_a_scale_ptrs{};
                    std::array<index_t, BaseUniGemmKernel::NumATensor> stride_a_scales{};
                    std::array<index_t, BaseUniGemmKernel::NumATensor> a_scale_block_k{};

                    static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                        // const auto* ptr = a_scale_base +
                        //                   static_cast<long_index_t>(sorted_row_start) * k_blocks;
                        // gate_a_scale_ptrs[i] = ptr;
                        gate_a_scale_ptrs[i] = a_scale_base;
                        stride_a_scales[i]   = gate_stride_a_scales;
                        a_scale_block_k[i]   = block_shape_k;
                    });

                    gate_gemm_arg.a_scale_ptr     = gate_a_scale_ptrs;
                    gate_gemm_arg.stride_A_scales = stride_a_scales;
                    gate_gemm_arg.a_scale_k_block_lengths = a_scale_block_k;
                }

                Run(gate_gemm_arg,
                    g_expert_ptr_up,
                    g_expert_scale_ptr_up,
                    block_idx_2d,
                    kargs.num_tokens,
                    input_token_id,
                    a_scale_token_id,
                    kargs.sorted_weight_ptr,
                    sorted_row_start);
    
                block_id = block_id + grid_size; // advance to next block
                // NOTE: this check is redundant but helps the compiler avoid spilling some VGPR
                if(block_id >= cum_grid_size)
                {
                    break; // exit the loop if all blocks are processed
                }
            }

        }

    }

};



template <typename TilePartitioner_, typename GemmPipeline_, typename EpiloguePipeline_>
struct FusedMoeStage2Kernel : public GroupedMoeGemmKernel<TilePartitioner_, GemmPipeline_, EpiloguePipeline_>
{
    // using Base = GroupedMoeGemmKernel<TilePartitioner_, GemmPipeline_, EpiloguePipeline_>;
    using BaseUniGemmKernel = UniversalMoeGemmKernel<TilePartitioner_, GemmPipeline_, EpiloguePipeline_>;
    
    using TilePartitioner  = remove_cvref_t<TilePartitioner_>;
    using GemmPipeline     = remove_cvref_t<GemmPipeline_>;
    using EpiloguePipeline = remove_cvref_t<EpiloguePipeline_>;

    using ADataType = remove_cvref_t<typename GemmPipeline::ADataType>;
    using BDataType = remove_cvref_t<typename GemmPipeline::BDataType>;
    using CDataType = remove_cvref_t<typename EpiloguePipeline::ODataType>;
    using AScaleDataType = remove_cvref_t<typename GemmPipeline::AScaleDataType>;
    using BScaleDataType = remove_cvref_t<typename GemmPipeline::BScaleDataType>;

    using TopkWeightDataType = float;   // assume topk weight is float

    // using SplitKBatchOffset = remove_cvref_t<typename BaseUniGemmKernel::SplitKBatchOffset>;

    using OffsetTile1DPartitioner = OffsettedTile1DPartitioner<TilePartitioner>;

    static constexpr bool UsePersistentKernel = GemmPipeline::UsePersistentKernel;

    static constexpr auto I0 = number<0>();
    static constexpr auto I1 = number<1>();
    static constexpr auto I2 = number<2>();
    static constexpr auto I3 = number<3>();
    static constexpr auto I4 = number<4>();

    struct FusedMoeStage2KernelArgs
    {
        const void* a_ptr;                 // [m*topk, n], input
        const void* a_scale_ptr;           // [m, 1], token scale
        const void* g_ptr;                 // [e, k, n]
        const void* g_scale_ptr;           // [e, 1, k], down scale
        const void* g_zp_ptr;              // [e, k, n/group], down zero-point
        const void* local_expert_mask_ptr; // [e], local_expert_mask_ptr for EP
        void* o_ptr;                       // [m, k]

        void* sorted_token_ids_ptr;  // [max_num_tokens_padded]
        void* sorted_weight_ptr;     // [max_num_tokens_padded]
        void* sorted_expert_ids_ptr; // [(max_num_tokens_padded + block_size - 1) / block_size]
        void* tokens_positions_per_expert_ptr;     // [num_experts*2], represents number of tokens and positions assigned to each expert
        void* num_sorted_tiles_ptr;  // [1]

        // void* tmp_out;              // tempary output

        ck_tile::index_t block_m;           // block_m, used to devide the input
        ck_tile::index_t hidden_size;       // k
        ck_tile::index_t intermediate_size; // n / TP, for Gate. and Up, Down is also this value
        ck_tile::index_t num_tokens;        // input number of tokens for current iteration
        ck_tile::index_t num_experts;       // number of groups
        ck_tile::index_t topk;              // need this?

        ck_tile::index_t stride_token;      // for output, stride for each row, should >= hidden_size
        
        ck_tile::index_t block_shape_n;     // quant block n size
        ck_tile::index_t block_shape_k;     // quant block k size

        const ck_tile::index_t* block_start_ptr;
        const ck_tile::index_t* block_end_ptr;
        const ck_tile::index_t* pre_tokens_ptr;
    };

    using Kargs = FusedMoeStage2KernelArgs;
    using Hargs = FusedMoeStage2HostArgs;

    CK_TILE_HOST static constexpr Kargs MakeKargs(const Hargs& hargs)
    {
        // TODO: hargs/kargs not guranteed to be the same
        return bit_cast<Kargs>(hargs);
    }

    [[nodiscard]] CK_TILE_HOST static const std::string GetName()
    {
        // clang-format off
        using P_ = GemmPipeline;

        return concat('_', "moe_stage2", gemm_prec_str<ADataType, BDataType>(),
                      concat('x', P_::MPerBlock, P_::NPerBlock, P_::KPerBlock),
                      concat('x', P_::GetVectorSizeA(), P_::GetVectorSizeB(), P_::GetVectorSizeC()),
                      concat('x', P_::kPadM, P_::kPadN, P_::kPadK),
                      (UsePersistentKernel ? "Persistent" : "NonPersistent"));
        // clang-format on
    }

    CK_TILE_DEVICE static void
    RunMoeGemm2WithPipelineSelection2LDS(const ADataType* a_ptr,
                                        const BDataType* b_ptr,
                                        CDataType* c_ptr,
                                        void* __restrict__ smem_ptr_0,
                                        void* __restrict__ smem_ptr_1,
                                        const UniversalMoeGemmKernelArgs<>& kargs,
                                        const index_t block_idx_m,
                                        const index_t block_idx_n,
                                        const index_t moe_num_tokens,
                                        const MoeStage2IndexAdaptor& index_adaptor,
                                        const void* sorted_weight_ptr,
                                        const index_t sorted_row_start)
    {
        std::array<const AScaleDataType*, BaseUniGemmKernel::NumATensor> as_scale_ptr
            [[maybe_unused]]{};
        std::array<const BScaleDataType*, BaseUniGemmKernel::NumBTensor> bs_scale_ptr
            [[maybe_unused]]{};
        if constexpr(GemmPipeline::UseABScale)
        {
            static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                as_scale_ptr[i] = static_cast<const AScaleDataType*>(kargs.a_scale_ptr[i]);
            });

            static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                bs_scale_ptr[i] = static_cast<const BScaleDataType*>(kargs.b_scale_ptr[i]);
            });
        }

        // Create Gemm tensor views, pad views and tile windows
        const auto& gemm_tensor_views_tuple =
            BaseUniGemmKernel::template MakeMoeGemm2TensorViews<EpiloguePipeline::MemoryOperation>(
                {a_ptr},
                {b_ptr},
                c_ptr,
                kargs,
                moe_num_tokens,
                as_scale_ptr,
                bs_scale_ptr);

        const auto& gemm_pad_views = BaseUniGemmKernel::MakeGemmPadViews(gemm_tensor_views_tuple);

        auto gemm_tile_windows = BaseUniGemmKernel::MakeMoeGemm2TileWindows(
            gemm_pad_views, block_idx_m, block_idx_n, index_adaptor);
        const auto& a_block_window = gemm_tile_windows.at(I0);
        const auto& b_block_window = gemm_tile_windows.at(I1);

        // Get hot-loop and tail configuration
        const index_t num_loop = __builtin_amdgcn_readfirstlane(
            TilePartitioner::GetLoopNum(kargs.K));
        const TailNumber tail_num = GemmPipeline::GetBlockLoopTailNum(num_loop);

        // Run GEMM pipeline with compile-time branching
        const auto& c_block_tile = [&]() {
            if constexpr(GemmPipeline::Preshuffle)
            {
                static_assert(false, "RunGemmWithPipelineSelection2LDS Not check!");

                if constexpr(GemmPipeline::UseABScale)
                {
                    const auto& a_scale_block_window =
                        gemm_tile_windows.at(I3);
                    const auto& b_scale_block_window =
                        gemm_tile_windows.at(I4);

                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1,
                                                              a_scale_block_window[I0],
                                                              b_scale_block_window[I0]);
                }
                else
                {
                    // Preshuffle version - without has_hot_loop parameter
                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1);
                }
            }
            else
            {
                // Regular version - with has_hot_loop parameter
                const bool has_hot_loop = GemmPipeline::BlockHasHotloop(num_loop);

                if constexpr(GemmPipeline::UseABScale)
                {
                    const auto& a_scale_block_window =
                        gemm_tile_windows.at(I3);
                    const auto& b_scale_block_window =
                        gemm_tile_windows.at(I4);

                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              has_hot_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1,
                                                              a_scale_block_window[I0],
                                                              b_scale_block_window[I0]);
                }
                else
                {
                    return GemmPipeline{}.template operator()(a_block_window[I0],
                                                              b_block_window[I0],
                                                              num_loop,
                                                              has_hot_loop,
                                                              tail_num,
                                                              smem_ptr_0,
                                                              smem_ptr_1);
                }
            }
        }();

        if (sorted_weight_ptr != nullptr) {
            // if (blockIdx.x == 0 && blockIdx.y == 0 && blockIdx.z == 0 && threadIdx.x == 0 && threadIdx.y == 0 && threadIdx.z == 0) {
            //     printf("$$ [RunMoeGemmWithPipelineSelection2LDS] moe_stage2: sorted_row_start = %d \n", sorted_row_start);
            // }

            auto* scale_m_ptr = reinterpret_cast<const TopkWeightDataType*>(sorted_weight_ptr) + sorted_row_start;
            constexpr auto scale_lengths = make_tuple(number<EpiloguePipeline::MPerIteration>{},
                                                      number<EpiloguePipeline::NPerIteration>{});
            constexpr auto scale_strides = make_tuple(number<1>{}, number<0>{});    // 0 means the scale will be broadcasted along this dim
            auto scale_desc = make_naive_tensor_descriptor(scale_lengths, scale_strides);
            auto scale_m_view =
                make_tensor_view<address_space_enum::global>(const_cast<TopkWeightDataType*>(scale_m_ptr), scale_desc);


            // Run Epilogue Pipeline
            auto& c_block_window = gemm_tile_windows.at(I2);
            EpiloguePipeline{}.template
            operator()<decltype(c_block_window), decltype(c_block_tile), decltype(tuple<>{})>(
                c_block_window, c_block_tile, tuple<>{}, smem_ptr_0, scale_m_view);

        } else {
            // if (blockIdx.x == 0 && blockIdx.y == 0 && blockIdx.z == 0 && threadIdx.x == 0 && threadIdx.y == 0 && threadIdx.z == 0) {
            //     printf("$$ [RunMoeGemmWithPipelineSelection2LDS] sorted_weight_ptr = nullptr! \n");
            // }

            // Run Epilogue Pipeline
            auto& c_block_window = gemm_tile_windows.at(I2);
            EpiloguePipeline{}.template
            operator()<decltype(c_block_window), decltype(c_block_tile), decltype(tuple<>{})>(
                c_block_window, c_block_tile, tuple<>{}, smem_ptr_0);
        }
        
    }

    CK_TILE_HOST_DEVICE static constexpr auto GetSmemSize() -> index_t
    {
        return max(GemmPipeline::GetSmemSize(), EpiloguePipeline::GetSmemSize());
    }

    CK_TILE_DEVICE void Run(const UniversalMoeGemmKernelArgs<>& kargs,
                            const tuple<index_t, index_t>& block_idx_2d,
                            const index_t moe_num_tokens,
                            const MoeStage2IndexAdaptor& index_adaptor,
                            const void* sorted_weight_ptr,
                            const index_t sorted_row_start) const
    {

        static_assert(GemmPipeline::DoubleSmemBuffer || !GemmPipeline::Preshuffle,
                      "SingleSmemBuffer and Preshuffle cannot both be enabled simultaneously!");

        const auto [iM, iN] = block_idx_2d;

        const index_t i_m = __builtin_amdgcn_readfirstlane(iM * TilePartitioner::MPerBlock);
        const index_t i_n = __builtin_amdgcn_readfirstlane(iN * TilePartitioner::NPerBlock);

        const ADataType* a_ptr = static_cast<const ADataType*>(kargs.as_ptr[0]);
        const BDataType* b_ptr = static_cast<const BDataType*>(kargs.bs_ptr[0]);
        CDataType* c_ptr = static_cast<CDataType*>(kargs.e_ptr);

        // allocate LDS
        __shared__ char smem_ptr_0[GetSmemSize()];

        if constexpr(GemmPipeline::DoubleSmemBuffer == true)
        {

            __shared__ char smem_ptr_1[GetSmemSize()];

            RunMoeGemm2WithPipelineSelection2LDS(a_ptr,
                                                b_ptr,
                                                c_ptr,
                                                smem_ptr_0,
                                                smem_ptr_1,
                                                kargs,
                                                i_m,
                                                i_n,
                                                moe_num_tokens,
                                                index_adaptor,
                                                sorted_weight_ptr,
                                                sorted_row_start);

        }
        else // SingleSmemBuffer
        {
            static_assert(false, "SingleSmemBuffer Not support!");
        }
    }

    CK_TILE_DEVICE index_t FindGroupId(Kargs& kargs,
                                       index_t block_id,
                                       index_t group_count) const
    {
        index_t left     = 0;
        index_t right    = group_count;
        index_t group_id = index_t((left + right) >> 1);

        while((!(block_id >= kargs.block_start_ptr[group_id] &&
                 block_id < kargs.block_end_ptr[group_id])) &&
              left <= right)
        {
            if(block_id < kargs.block_start_ptr[group_id])
            {
                right = group_id;
            }
            else
            {
                left = group_id;
            }
            group_id = index_t((left + right) >> 1);
        }

        return group_id;
    }
    
    // For non-persistent kernels
    template <bool U = UsePersistentKernel, typename = std::enable_if_t<!U>>
    CK_TILE_DEVICE void operator()(Kargs kargs, const index_t group_count) const
    {
        _Pragma("clang diagnostic push")
        _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");

        index_t num_sorted_tiles = __builtin_amdgcn_readfirstlane(
                *reinterpret_cast<const index_t*>(kargs.num_sorted_tiles_ptr));
        num_sorted_tiles = num_sorted_tiles / kargs.block_m;

        constexpr index_t token_mask = (index_t{1} << 24) - 1;

        const int gemm_N = kargs.hidden_size;
        const int gemm_K = kargs.intermediate_size;

        index_t block_shape_k, block_shape_n, k_blocks, n_blocks;
        if constexpr(GemmPipeline::UseABScale) {
            block_shape_k = kargs.block_shape_k > 0 ? kargs.block_shape_k : static_cast<index_t>(1);
            block_shape_n = kargs.block_shape_n > 0 ? kargs.block_shape_n : static_cast<index_t>(1);
            k_blocks = ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_K), block_shape_k);
            n_blocks = ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_N), block_shape_n);
        }

        const index_t block_id   = ck_tile::get_block_1d_id();
        const index_t group_id = FindGroupId(kargs, block_id, group_count);


        // group_count = num_experts
        const index_t expert_start = __builtin_amdgcn_readfirstlane(reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id + group_count]);
        const int tokens_num = __builtin_amdgcn_readfirstlane(reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id]);
        const int pre_token_num = __builtin_amdgcn_readfirstlane(
            reinterpret_cast<const index_t*>(kargs.pre_tokens_ptr)[group_id]);
        if (tokens_num <= 0) {
            return;
        }

        const int gemm_M = tokens_num;

        // get expert start offset
        const auto c_coord = EpiloguePipeline::GetTileDistributionCoord(); // per-thread output row/col within the tile
        // const index_t expert_start = tile_start * kargs.block_m;

        const ADataType* a_states_ptr = reinterpret_cast<const ADataType*>(kargs.a_ptr) +
            static_cast<long_index_t>(pre_token_num) * gemm_K;      // make sure: stride_input = gemm_K

        const BDataType* b_weight_ptr = reinterpret_cast<const BDataType*>(kargs.g_ptr) +
            static_cast<long_index_t>(group_id) * gemm_N * gemm_K;

        CDataType* out_ptr = reinterpret_cast<CDataType*>(kargs.o_ptr);

        auto gemm_arg =
            UniversalMoeGemmKernelArgs<>{{a_states_ptr},
                                        {b_weight_ptr},
                                        out_ptr,
                                        gemm_M,
                                        gemm_N,
                                        gemm_K,
                                        {gemm_K},     // stride_a
                                        {gemm_K},     // stride_b
                                        kargs.stride_token};   //stride_c

        if constexpr(GemmPipeline::UseABScale)
        {
            std::array<const void*, BaseUniGemmKernel::NumATensor> a_scale_ptrs{};
            std::array<const void*, BaseUniGemmKernel::NumBTensor> b_scale_ptrs{};
            std::array<index_t, BaseUniGemmKernel::NumATensor> stride_a_scales{};
            std::array<index_t, BaseUniGemmKernel::NumBTensor> stride_b_scales{};
            std::array<index_t, BaseUniGemmKernel::NumATensor> a_scale_block_k{};
            std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_k{};
            std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_n{};

            static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                const auto* a_scale_base = static_cast<const AScaleDataType*>(kargs.a_scale_ptr);
                const auto* a_scale_ptr = a_scale_base + static_cast<long_index_t>(pre_token_num) * k_blocks;
                
                a_scale_ptrs[i]    = static_cast<const void*>(a_scale_ptr);
                stride_a_scales[i] = k_blocks;
                a_scale_block_k[i] = block_shape_k;
            });

            static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                const auto* b_scale_base = static_cast<const BScaleDataType*>(kargs.g_scale_ptr);
                const auto expert_offset = static_cast<long_index_t>(group_id) * n_blocks * k_blocks;
                b_scale_ptrs[i] = static_cast<const void*>(b_scale_base + expert_offset);
                stride_b_scales[i] = k_blocks;
                b_scale_block_k[i] = block_shape_k;
                b_scale_block_n[i] = block_shape_n;
            });

            gemm_arg.a_scale_ptr     = a_scale_ptrs;
            gemm_arg.b_scale_ptr     = b_scale_ptrs;
            gemm_arg.stride_A_scales = stride_a_scales;
            gemm_arg.stride_B_scales = stride_b_scales;
            gemm_arg.a_scale_k_block_lengths = a_scale_block_k;
            gemm_arg.b_scale_k_block_lengths = b_scale_block_k;
            gemm_arg.b_scale_n_block_lengths = b_scale_block_n;
        }

        index_t cum_grid_size = TilePartitioner::GridSize(gemm_M, gemm_N);

        const auto block_idx_2d = OffsetTile1DPartitioner::GetOffsetedTileIndex(
            0, gemm_M, gemm_N, block_id % cum_grid_size);

        // get token_id according to block_idx_2d
        // MPerBlock需与moe sorting中的block_m保持一致，否则最后的block可能取到<sorted_token_ids_ptr>越界的token_id，
        // 因group gemm中tile_distribution是按MPerBlock划分的
        const auto [iM, iN] = block_idx_2d;

        const index_t i_m = __builtin_amdgcn_readfirstlane(iM * TilePartitioner::MPerBlock);
        const index_t block_origin = expert_start + i_m; // 当前 block 的首行
        // const index_t local_row    = c_coord[number<0>{}];              // 线程在 tile 内的起始行
        const auto token_ids_ptr = reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr);
        const MoeStage2IndexAdaptor index_adaptor{token_ids_ptr, block_origin};


        Run(gemm_arg,
            block_idx_2d,
            kargs.num_tokens,
            index_adaptor,
            kargs.sorted_weight_ptr,
            block_origin);

    }


    // For persistent kernels
    template <bool U   = UsePersistentKernel,
              typename = std::enable_if_t<U>,
              typename = void> // extra template parameter to avoid redefinition
    CK_TILE_DEVICE void operator()(Kargs kargs, const index_t group_count) const
    {

        _Pragma("clang diagnostic push")
        _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");

        const index_t grid_size = ck_tile::get_grid_size();
        index_t num_sorted_tiles = __builtin_amdgcn_readfirstlane(
                *reinterpret_cast<const index_t*>(kargs.num_sorted_tiles_ptr));
        num_sorted_tiles = num_sorted_tiles / kargs.block_m;


        int pre_token_num = 0;
        constexpr index_t token_mask = (index_t{1} << 24) - 1;

        const int gemm_N = kargs.hidden_size;
        const int gemm_K = kargs.intermediate_size;

        index_t block_shape_k, block_shape_n, k_blocks, n_blocks;
        if constexpr(GemmPipeline::UseABScale) {
            block_shape_k = kargs.block_shape_k > 0 ? kargs.block_shape_k : static_cast<index_t>(1);
            block_shape_n = kargs.block_shape_n > 0 ? kargs.block_shape_n : static_cast<index_t>(1);
            k_blocks = ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_K), block_shape_k);
            n_blocks = ck_tile::integer_divide_ceil(static_cast<index_t>(gemm_N), block_shape_n);
        }

        for(index_t group_id = 0; group_id < group_count; ++group_id)
        {
            // group_count = num_experts
            const index_t expert_start = __builtin_amdgcn_readfirstlane(reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id + group_count]);
            const int tokens_num = __builtin_amdgcn_readfirstlane(reinterpret_cast<const index_t*>(kargs.tokens_positions_per_expert_ptr)[group_id]);
            if (tokens_num <= 0) {
                continue;
            }

            const int gemm_M = tokens_num;

            // get expert start offset
            const auto c_coord = EpiloguePipeline::GetTileDistributionCoord(); // per-thread output row/col within the tile
            // const index_t expert_start = tile_start * kargs.block_m;

            const auto token_offset = pre_token_num;
            const ADataType* a_states_ptr = reinterpret_cast<const ADataType*>(kargs.a_ptr) +
                static_cast<long_index_t>(token_offset) * gemm_K;      // make sure: stride_input = gemm_K

            pre_token_num += tokens_num;

            const BDataType* b_weight_ptr = reinterpret_cast<const BDataType*>(kargs.g_ptr) +
                static_cast<long_index_t>(group_id) * gemm_N * gemm_K;

            CDataType* out_ptr = reinterpret_cast<CDataType*>(kargs.o_ptr);

            auto gemm_arg =
                UniversalMoeGemmKernelArgs<>{{a_states_ptr},
                                          {b_weight_ptr},
                                          out_ptr,
                                          gemm_M,
                                          gemm_N,
                                          gemm_K,
                                          {gemm_K},     // stride_a
                                          {gemm_K},     // stride_b
                                          kargs.stride_token};   //stride_c

            if constexpr(GemmPipeline::UseABScale)
            {
                std::array<const void*, BaseUniGemmKernel::NumATensor> a_scale_ptrs{};
                std::array<const void*, BaseUniGemmKernel::NumBTensor> b_scale_ptrs{};
                std::array<index_t, BaseUniGemmKernel::NumATensor> stride_a_scales{};
                std::array<index_t, BaseUniGemmKernel::NumBTensor> stride_b_scales{};
                std::array<index_t, BaseUniGemmKernel::NumATensor> a_scale_block_k{};
                std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_k{};
                std::array<index_t, BaseUniGemmKernel::NumBTensor> b_scale_block_n{};

                static_for<0, BaseUniGemmKernel::NumATensor, 1>{}([&](auto i) {
                    const auto* a_scale_base = static_cast<const AScaleDataType*>(kargs.a_scale_ptr);
                    const auto* a_scale_ptr = a_scale_base + static_cast<long_index_t>(token_offset) * k_blocks;
                    
                    a_scale_ptrs[i]    = static_cast<const void*>(a_scale_ptr);
                    stride_a_scales[i] = k_blocks;
                    a_scale_block_k[i] = block_shape_k;
                });

                static_for<0, BaseUniGemmKernel::NumBTensor, 1>{}([&](auto i) {
                    const auto* b_scale_base = static_cast<const BScaleDataType*>(kargs.g_scale_ptr);
                    const auto expert_offset = static_cast<long_index_t>(group_id) * n_blocks * k_blocks;
                    b_scale_ptrs[i] = static_cast<const void*>(b_scale_base + expert_offset);
                    stride_b_scales[i] = k_blocks;
                    b_scale_block_k[i] = block_shape_k;
                    b_scale_block_n[i] = block_shape_n;
                });

                gemm_arg.a_scale_ptr     = a_scale_ptrs;
                gemm_arg.b_scale_ptr     = b_scale_ptrs;
                gemm_arg.stride_A_scales = stride_a_scales;
                gemm_arg.stride_B_scales = stride_b_scales;
                gemm_arg.a_scale_k_block_lengths = a_scale_block_k;
                gemm_arg.b_scale_k_block_lengths = b_scale_block_k;
                gemm_arg.b_scale_n_block_lengths = b_scale_block_n;
            }


            index_t block_id = ck_tile::get_block_1d_id();
            index_t cum_grid_size = TilePartitioner::GridSize(gemm_M, gemm_N);

            while(block_id < cum_grid_size)
            {
                const auto block_idx_2d = OffsetTile1DPartitioner::GetOffsetedTileIndex(
                    0, gemm_M, gemm_N, block_id % cum_grid_size);

                // get token_id according to block_idx_2d
                // MPerBlock需与moe sorting中的block_m保持一致，否则最后的block可能取到<sorted_token_ids_ptr>越界的token_id，
                // 因group gemm中tile_distribution是按MPerBlock划分的
                const auto [iM, iN] = block_idx_2d;

                const index_t i_m = __builtin_amdgcn_readfirstlane(iM * TilePartitioner::MPerBlock);
                const index_t block_origin = expert_start + i_m; // 当前 block 的首行
                // const index_t local_row    = c_coord[number<0>{}];              // 线程在 tile 内的起始行
                const auto token_ids_ptr = reinterpret_cast<const index_t*>(kargs.sorted_token_ids_ptr);
                const MoeStage2IndexAdaptor index_adaptor{token_ids_ptr, block_origin};


                Run(gemm_arg,
                    block_idx_2d,
                    kargs.num_tokens,
                    index_adaptor,
                    kargs.sorted_weight_ptr,
                    block_origin);
    
                block_id = block_id + grid_size; // advance to next block
                // NOTE: this check is redundant but helps the compiler avoid spilling some VGPR
                if(block_id >= cum_grid_size)
                {
                    break; // exit the loop if all blocks are processed
                }
            }

        }

    }

};

}