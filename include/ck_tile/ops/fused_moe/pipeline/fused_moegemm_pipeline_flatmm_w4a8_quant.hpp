// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common/tensor_layout.hpp"
#include "ck_tile/ops/fused_moe/pipeline/fused_moegemm_pipeline_flatmm_w4a8_quant_policy.hpp"
#include "ck_tile/ops/moe_quant.hpp"

namespace ck_tile {

/*
This pipeline deal with a gemm(actually 2 gemm) with one very small(token), one very big(weight)
we need to design the pipeline such that all waves along gemm-N dim (gemm-m only 1 wave)

    <----- gemm-N ------>
    +----+----+----+----+
    | w0 | w1 | w2 | w3 | gemm-m
    +----+----+----+----+
*/
template <typename Problem_, typename Policy_ = FusedMoeGemmPipelineFlatmmW4A8QuantPolicy>
struct FusedMoeGemmPipeline_Flatmm_W4A8_quant
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
    using AQuantDataType       = typename Problem::GDataType;
    using GScaleDataType       = typename Problem::GScaleDataType;
    using DScaleDataType       = typename Problem::DScaleDataType;
    using GZeroPointDataType   = typename Problem::GZeroPointDataType;
    using DZeroPointDataType   = typename Problem::DZeroPointDataType;
    using YSmoothScaleDataType = typename Problem::YSmoothScaleDataType;
    using TopkWeightDataType   = typename Problem::TopkWeightDataType;
    using IndexDataType        = typename Problem::IndexDataType;
    using YDataType            = typename Problem::YDataType;

    using Traits = typename Problem::Traits;

    static constexpr bool IsGateOnly          = Traits::IsGateOnly;
    static constexpr bool UseSmoothQuant      = Traits::UseSmoothQuant;
    static constexpr bool PadHiddenSize       = Traits::PadHiddenSize;
    static constexpr bool PadIntermediateSize = Traits::PadIntermediateSize;

    static constexpr index_t kAlignmentA = Policy::template GetAlignment_A_input<Problem>();
    static constexpr index_t kAlignmentG = Policy::template GetAlignment_G<Problem>();
    static constexpr index_t kAlignmentD = Policy::template GetAlignment_D<Problem>();
    static constexpr index_t kAlignmentO = Policy::template GetAlignment_O<Problem>();
    static constexpr index_t NumPrefetch = Problem::NumPrefetch;

    static constexpr index_t SLD_A = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::SLD_A);
    static constexpr index_t GLD_A = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::GLD_A);
    static constexpr index_t GLD_B = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::GLD_B);
    static constexpr index_t GST_O = static_cast<index_t>(FusedMoeGemmPipelineSequencerEnum::GST_O);

    static constexpr index_t Block_M0 = BlockShape::Block_M0;
    static constexpr index_t Block_N0 = BlockShape::Block_N0;
    static constexpr index_t Block_K0 = BlockShape::Block_K0;
    static constexpr index_t Block_N1 = BlockShape::Block_N1;
    static constexpr index_t Block_K1 = BlockShape::Block_K1;

    static constexpr index_t QuantBlockSizeK_ = Problem::QuantBlockSizeK;

    static constexpr index_t Block_N0_P =  Block_N0 / Problem::PackFactor;
    static constexpr index_t Block_K0_P =  Block_K0 / Problem::PackFactor;
    static constexpr index_t Block_N1_P =  Block_N1 / Problem::PackFactor;
    static constexpr index_t Block_K1_P =  Block_K1 / Problem::PackFactor;
    static constexpr index_t Block_K0_Group =  Block_K0 / QuantBlockSizeK_;
    static constexpr index_t Block_K1_Group =  Block_K1 / QuantBlockSizeK_;

    // Temparily for block_k = 128 or 64;
    static constexpr index_t Block_Dividor_0 = (Block_K0 == 128) ? (QuantBlockSizeK_ / 32) : (QuantBlockSizeK_ / 16);
    static constexpr index_t Block_Dividor_1 = (Block_K1 == 128) ? (QuantBlockSizeK_ / 32) : (QuantBlockSizeK_ / 16);

    static constexpr index_t Gemm0_Thread_Dividor = Problem::PackFactor / Problem::Gemm0NInterleave;

    static constexpr auto I0 = number<0>{};
    static constexpr auto I1 = number<1>{};
    static constexpr auto I2 = number<2>{};
    static constexpr auto I3 = number<3>{};

    // for quanize input A
    static constexpr index_t QuantLoop_0 = number<Block_K0/QuantBlockSizeK_>{};
    static constexpr index_t QuantLoop_1 = number<Block_K1/QuantBlockSizeK_>{};     // Block_N0 == Block_K1
    static constexpr index_t QT_Vector_N_ = 4;
    // constexpr static index_t QT_Repeat_M_ = Block_M0 / BlockShape::NumWarps;
    static constexpr bool QT_kPadM      = false;    // always no need to pad along M
    static constexpr bool QT_kPadN      = true;

    using QT_BlockTile  = ck_tile::sequence<Block_M0, QuantBlockSizeK_>;    // <16, 64>
    using QT_BlockWarps = ck_tile::sequence<BlockShape::NumWarps, 1>;       // warps along M = 4, warps along N = 1
    using QT_WarpTile   = ck_tile::sequence<4, get_warp_size() / 4 * QT_Vector_N_>;  //get_warp_size() / 4 * QT_Vector_N_ == QuantBlockSizeK_
    //using QT_WarpTile   = ck_tile::sequence<2, warpSize / 2 * QT_Vector_N_>;  //warpSize / 2 * QT_Vector_N_ == QuantBlockSizeK_
    // using QT_WarpTile   = ck_tile::sequence<1, warpSize * QT_Vector_N_>;
    using QT_Vector     = ck_tile::sequence<1, QT_Vector_N_>;
    using QT_Shape = ck_tile::Generic2dBlockShape<QT_BlockTile, QT_BlockWarps, QT_WarpTile, QT_Vector>; // <<128,128>, <4, 1>, <1, 128>, <1, 2>>;

    using QuantPipelineProblem = ck_tile::quantPipelineProblem<
        ADataType,
        AScaleDataType,
        float,
        AQuantDataType,
        QT_Shape,
        QT_kPadN>;
    using QuantPipeline = ck_tile::quantPipelineOnePass<QuantPipelineProblem>;

    CK_TILE_HOST_DEVICE static constexpr index_t GetQuantPipeSmemSize() { return QuantPipeline::GetSmemSize(); }    // this is the size of smem used by quant pipeline internally

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

    using Vec16x2_type = std::conditional_t<std::is_same_v<ADataType, ck_tile::bf16_t>, bf16x2_t, fp16x2_t>;

    CK_TILE_HOST_DEVICE static Vec16x2_type pk_int4_to_vec(pk_int4_t in) {
        if constexpr (std::is_same_v<ADataType, ck_tile::bf16_t>) {
            return pk_int4_t_to_bfloat16x2_t(in);
        } else {
            return pk_int4_t_to_halfx2_t(in);
        }
    }

    CK_TILE_HOST_DEVICE static Vec16x2_type pk_uint4_to_vec(pk_int4_t in) {
        if constexpr (std::is_same_v<ADataType, ck_tile::bf16_t>) {
            return pk_uint4_t_to_bfloat16x2_t(in);
        } else {
            return pk_uint4_t_to_halfx2_t(in);
        }
    }

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

    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_quant_out()
    {
        // for gemm0, smem size is Block_M0 * Block_K0, for gemm1, smem size is Block_M0 * Block_N0
        constexpr index_t val = BlockShape::Block_K0 >= BlockShape::Block_N0 ? BlockShape::Block_K0 : BlockShape::Block_N0;
        return Policy::template GetSmemSize_A<Problem>() / Block_K0 * val;
    }
    CK_TILE_HOST_DEVICE static constexpr ck_tile::index_t GetSmemSize_scale_out()
    {
        return GetSmemSize_quant_out() / QuantBlockSizeK_;
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
              typename QuantWindow,
              typename ScaleWindow>
    CK_TILE_DEVICE void quantize_a_0(AWindow& a_window_,
                                     QuantWindow& quant_window_,
                                     ScaleWindow& scale_window_,
                                     CK_TILE_LDS_ADDR void* smem_quant_inter)
    {
        static_assert(Block_K0 % QuantBlockSizeK_ == 0, "Block_K0 must be multiple of QuantBlockSizeK !");

        if constexpr(QuantLoop_0 > 1) {

            static_for<0, QuantLoop_0, 1>{}([&](auto i) {
                (void)i; // to avoid unused variable warning
                QuantPipeline{}(a_window_, scale_window_, quant_window_, QuantBlockSizeK_, smem_quant_inter);

                move_tile_window(a_window_, {number<0>{}, number<QuantBlockSizeK_>{}});
                move_tile_window(quant_window_, {number<0>{}, number<QuantBlockSizeK_>{}});
                move_tile_window(scale_window_, {number<Block_M0>{}});
            });

            a_window_.set_window_origin({0, 0});
            quant_window_.set_window_origin({0, 0});
            scale_window_.set_window_origin({0});

        } else {
            QuantPipeline{}(a_window_, scale_window_, quant_window_, QuantBlockSizeK_, smem_quant_inter);
        }
        
        block_sync_lds();
    }

    template <typename AWindow,
              typename QuantWindow,
              typename ScaleWindow>
    CK_TILE_DEVICE void quantize_a_1(AWindow& a_window_,
                                     QuantWindow& quant_window_,
                                     ScaleWindow& scale_window_,
                                     CK_TILE_LDS_ADDR void* smem_quant_inter)
    {
        static_assert(Block_K0 % QuantBlockSizeK_ == 0, "Block_K0 must be multiple of QuantBlockSizeK !");

        if constexpr(QuantLoop_1 > 1) {

            static_for<0, QuantLoop_1, 1>{}([&](auto i) {
                (void)i; // to avoid unused variable warning
                QuantPipeline{}(a_window_, scale_window_, quant_window_, QuantBlockSizeK_, smem_quant_inter);

                move_tile_window(a_window_, {number<0>{}, number<QuantBlockSizeK_>{}});
                move_tile_window(quant_window_, {number<0>{}, number<QuantBlockSizeK_>{}});
                move_tile_window(scale_window_, {number<Block_M0>{}});
            });

            a_window_.set_window_origin({0, 0});
            quant_window_.set_window_origin({0, 0});
            scale_window_.set_window_origin({0});

        } else {
            QuantPipeline{}(a_window_, scale_window_, quant_window_, QuantBlockSizeK_, smem_quant_inter);
        }
        
        block_sync_lds();
    }

    template <int thread_buf_size,
              typename InputTensor,
              typename OutTensor,
              typename GZeroPointDataType>
    CK_TILE_DEVICE void prepare_gemm0_B(InputTensor& input,
                                          OutTensor& output,
                                          GZeroPointDataType* zp_ptr,
                                          index_t loop_index,
                                          index_t hidden_size_group)
    {
        static_assert(std::is_same_v<ADataType, ck_tile::bf16_t> || std::is_same_v<ADataType, ck_tile::fp16_t>,
                      "ADataType must be bf16 or fp16 for FusedMoeGemmPipeline_Flatmm_W4A16_quant");

        if (zp_ptr == nullptr) {
            for(int i =0; i < thread_buf_size; i++) {
                int8_t in = input.get_thread_buffer()[i];
                auto out_vec = pk_int4_t_to_int8x2_t(pk_int4_t(in));

                output.get_thread_buffer()[i*2] = out_vec.y;
                output.get_thread_buffer()[i*2 + 1] = out_vec.x;
            }

        // has zero points
        } else {
            using WarpGemm0  = decltype(Policy::template GetWarpGemm0<Problem>());
            auto warp_gemm0 = WarpGemm0{};
            using WarpGemmImp = typename remove_cvref_t<decltype(warp_gemm0)>::WarpGemmAttribute::Impl;
            index_t N_lane = WarpGemmImp::kBNLane;
            // index_t K_lane = WarpGemmImp::kABKLane;

            GZeroPointDataType* block_zp_ptr = zp_ptr + loop_index * Block_K0_Group;

            index_t thread_off = hidden_size_group * Problem::Gemm0NInterleave;
            index_t warp_off = get_warp_id() * (thread_off * N_lane) / Problem::PackFactor;
            index_t thread_pos = (threadIdx.x % N_lane / Gemm0_Thread_Dividor) * hidden_size_group + threadIdx.x % get_warp_size() / N_lane / Block_Dividor_0;
            index_t zp_idx = warp_off + thread_pos;
            GDataType zero_point = 0;

            int8_t zp_in = block_zp_ptr[zp_idx];
            auto zp_tmp = pk_uint4_t_to_int8x2_t(pk_int4_t(zp_in));

            constexpr index_t buf_sz_one = thread_buf_size / Problem::Gemm0NInterleave;

            for(int i =0; i < thread_buf_size; i++) {

                if constexpr(Problem::Gemm0NInterleave == 2) {
                    if (i < buf_sz_one) {
                        zero_point = zp_tmp.y;
                    } else {
                        zero_point = zp_tmp.x;
                    }
                } else if constexpr(Problem::Gemm0NInterleave == 1) {
                    if (threadIdx.x % 2 == 0) {
                        zero_point = zp_tmp.y;
                    } else {
                        zero_point = zp_tmp.x;
                    }
                }

                int8_t in = input.get_thread_buffer()[i];
                auto out_vec = pk_uint4_t_to_int8x2_t(pk_int4_t(in));

                output.get_thread_buffer()[i*2] = (out_vec.y - zero_point);
                output.get_thread_buffer()[i*2 + 1] = (out_vec.x - zero_point);
            }
        }

        
    }

        template <int thread_buf_size,
              typename InputTensor,
              typename OutTensor,
              typename DZeroPointDataType>
    CK_TILE_DEVICE void prepare_gemm1_B(InputTensor& input,
                                        OutTensor& output,
                                        DZeroPointDataType* zp_ptr,
                                        index_t loop_index,
                                        index_t intermediate_size_group)
    {

        if (zp_ptr == nullptr) {
            for(int i =0; i < thread_buf_size; i++) {
                int8_t in = input.get_thread_buffer()[i];
                auto out_vec = pk_int4_t_to_int8x2_t(pk_int4_t(in));

                output.get_thread_buffer()[i*2] = out_vec.y;
                output.get_thread_buffer()[i*2 + 1] = out_vec.x;
            }
        } else {
            using WarpGemm1  = decltype(Policy::template GetWarpGemm1<Problem>());
            auto warp_gemm1 = WarpGemm1{};
            using warpGemmAttr = typename remove_cvref_t<decltype(warp_gemm1)>::WarpGemmAttribute;
            using WarpGemmImp = warpGemmAttr::Impl;
            index_t N_lane = WarpGemmImp::kBNLane;

            static_assert(warpGemmAttr::NRepeat == 2 || warpGemmAttr::NRepeat == 1,
                      "warpGemmAttr::NRepeat must be 1 or 2 for FusedMoeGemmPipeline_Flatmm_W4A8_quant");

            index_t repeat_off = intermediate_size_group * N_lane;
            index_t warp_off = get_warp_id() * (repeat_off * warpGemmAttr::NRepeat) / Problem::PackFactor;
            index_t thread_pos = (threadIdx.x % N_lane / Problem::PackFactor) * intermediate_size_group + threadIdx.x % get_warp_size() / N_lane / Block_Dividor_1;
            index_t zp_idx = warp_off + thread_pos;

            DZeroPointDataType* block_zp_ptr = zp_ptr + Block_N1_P * intermediate_size_group * loop_index;

            int8_t zp_in_1 = block_zp_ptr[zp_idx];
            auto zp_tmp_1 = pk_uint4_t_to_int8x2_t(pk_int4_t(zp_in_1));
            
            constexpr index_t buf_sz_one = thread_buf_size / warpGemmAttr::NRepeat;
            DDataType zero_point = 0;

            for(int i =0; i < buf_sz_one; i++) {
                if (threadIdx.x % 2 == 0) {
                    zero_point = zp_tmp_1.y;
                } else {
                    zero_point = zp_tmp_1.x;
                }

                int8_t in = input.get_thread_buffer()[i];
                auto out_vec = pk_uint4_t_to_int8x2_t(pk_int4_t(in));

                output.get_thread_buffer()[i*2] = (out_vec.y - zero_point);
                output.get_thread_buffer()[i*2 + 1] = (out_vec.x - zero_point);
            }

            if constexpr (warpGemmAttr::NRepeat == 2) {
                index_t buf_sz_one_off = N_lane * intermediate_size_group / Problem::PackFactor;
                int8_t zp_in_2 = block_zp_ptr[zp_idx + buf_sz_one_off];
                auto zp_tmp_2 = pk_uint4_t_to_int8x2_t(pk_int4_t(zp_in_2));

                for (int i = buf_sz_one; i < thread_buf_size; i++) {
                    if (threadIdx.x % 2 == 0) {
                        zero_point = zp_tmp_2.y;
                    } else {
                        zero_point = zp_tmp_2.x;
                    }

                    int8_t in = input.get_thread_buffer()[i];
                    auto out_vec = pk_uint4_t_to_int8x2_t(pk_int4_t(in));

                    output.get_thread_buffer()[i*2] = (out_vec.y - zero_point);
                    output.get_thread_buffer()[i*2 + 1] = (out_vec.x - zero_point);
                }
            }
        }
        
    }

    template <int thread_buf_size,
              typename ACCTensor,
              typename ACCDequantTensor>
    CK_TILE_DEVICE void dequantize_acc0(ACCTensor& acc_0,
                                        ACCDequantTensor& acc_0_dequant,
                                        const AScaleDataType* a_scale_ptr,
                                        const GScaleDataType* b_scale_ptr,
                                        index_t hidden_size_group,
                                        index_t loop_index)
    {
        static_assert(Block_K0 == QuantBlockSizeK_, "Block_K0 must be equal to QuantBlockSizeK_ for dequantize_acc0!");
        static_assert(BlockShape::NumWarps == 4, "BlockShape::NumWarps must be 4 for dequantize_acc0!");
        static_assert(Problem::Gemm0NInterleave == 1, "Problem::Gemm0NInterleave must be 1 for dequantize_acc0!");


        using WarpGemm0  = decltype(Policy::template GetWarpGemm0<Problem>());
        auto warp_gemm0 = WarpGemm0{};
        using WarpGemmImp = typename remove_cvref_t<decltype(warp_gemm0)>::WarpGemmAttribute::Impl;
        index_t N_lane = WarpGemmImp::kCNLane;  // should be 4
        index_t kN_perLane = WarpGemmImp::kCN0PerLane; // should be 4

        index_t warp_off = hidden_size_group * N_lane * kN_perLane * get_warp_id();
        index_t base_off = loop_index * Block_K0_Group + warp_off;
        index_t tid_in_warp = threadIdx.x % get_warp_size();
        index_t element_off = 4 * hidden_size_group;    // check the layout of matrix C in int8 gemm 

        AScaleDataType a_scale = a_scale_ptr[threadIdx.x % 16];     // LDS address space.

        for(int i =0; i < thread_buf_size; i++) {
            index_t idx = base_off + tid_in_warp / 16 * hidden_size_group + i * element_off;
            GScaleDataType b_scale = b_scale_ptr[idx];
            float final_scale = static_cast<float>(a_scale) * static_cast<float>(b_scale);
            float acc = static_cast<float>(acc_0.get_thread_buffer()[i]) * final_scale;
            acc_0_dequant.get_thread_buffer()[i] += acc;
            acc_0.get_thread_buffer()[i] = 0;
        }

    }

    template <int thread_buf_size,
              typename ACCTensor,
              typename ACCDequantTensor>
    CK_TILE_DEVICE void dequantize_acc1s(ACCTensor& acc_1s,
                                ACCDequantTensor& acc_1s_dequant,
                                const AScaleDataType* a_scale_ptr,
                                const DScaleDataType* b_scale_ptr,
                                index_t intermediate_size_group,
                                index_t loop_index)
    {
        static_assert(Block_K1 == QuantBlockSizeK_, "Block_K1 must be equal to QuantBlockSizeK_ for dequantize_acc1s!");
        static_assert(BlockShape::NumWarps == 4, "BlockShape::NumWarps must be 4 for dequantize_acc1s!");

        using WarpGemm1  = decltype(Policy::template GetWarpGemm1<Problem>());
        auto warp_gemm1 = WarpGemm1{};
        using warpGemmAttr = typename remove_cvref_t<decltype(warp_gemm1)>::WarpGemmAttribute;
        using WarpGemmImp = warpGemmAttr::Impl;
        index_t N_lane = WarpGemmImp::kCNLane;

        static_assert(warpGemmAttr::NRepeat == 2 || warpGemmAttr::NRepeat == 1,
                      "warpGemmAttr::NRepeat must be 1 or 2 for FusedMoeGemmPipeline_Flatmm_W4A8_quant");

        // ！！ must aware that the gemm1 out is Transposed C.

        index_t one_warp_off = intermediate_size_group * N_lane;
        index_t loop_offset = loop_index * intermediate_size_group * Block_N1;
        index_t warp_offset = one_warp_off * warpGemmAttr::NRepeat * get_warp_id();      //WarpGemmImp::kCNLane =16
        index_t b_idx = loop_offset + warp_offset + (threadIdx.x % N_lane * intermediate_size_group);

        DScaleDataType b_scale = b_scale_ptr[b_idx]; // LDS address space.
        constexpr index_t buf_sz_one = thread_buf_size / warpGemmAttr::NRepeat;

        for (int i = 0; i < buf_sz_one; i++) {
            index_t a_idx = threadIdx.x % get_warp_size() / N_lane + (i % 4 * 4);

            AScaleDataType a_scale = a_scale_ptr[a_idx];
            acc_1s_dequant.get_thread_buffer()[i] =
                static_cast<ODataType>(static_cast<float>(acc_1s.get_thread_buffer()[i]) *
                                    static_cast<float>(a_scale) * static_cast<float>(b_scale));
        }

        if constexpr (warpGemmAttr::NRepeat == 2) {
            b_scale = b_scale_ptr[b_idx + one_warp_off];

            int j = 0;
            for (int i = buf_sz_one; i < thread_buf_size; i++) {
                index_t a_idx = threadIdx.x % get_warp_size() / N_lane + ((j++) % 4 * 4);

                AScaleDataType a_scale = a_scale_ptr[a_idx];
                acc_1s_dequant.get_thread_buffer()[i] =
                    static_cast<ODataType>(static_cast<float>(acc_1s.get_thread_buffer()[i]) *
                                        static_cast<float>(a_scale) * static_cast<float>(b_scale));
            }

        }
    }

    template <typename AWindow,
              typename GWindow,
              typename DWindow,
              typename GScaleWindow,
              typename DScaleWindow,
              typename GZeroPointWindow,
              typename DZeroPointWindow,
              typename OWindow,
              typename TopkArrayType>
    CK_TILE_DEVICE auto
    operator()(const AWindow& a_window_,
               const GWindow& g_window_,
               const DWindow& d_window_,
               const GScaleWindow& g_scale_window_,
               const DScaleWindow& d_scale_window_,
               const GZeroPointWindow& g_zp_window_,
               const DZeroPointWindow& d_zp_window_,
               OWindow& o_window_,
               TopkArrayType& topk_weights /*topk_weight array for atomic, must be f32*/,
               CK_TILE_LDS_ADDR void* smem,
               CK_TILE_LDS_ADDR void* smem_quant_inter,
               CK_TILE_LDS_ADDR AQuantDataType* smem_quant,
               CK_TILE_LDS_ADDR AScaleDataType* smem_scale,
               index_t hidden_size,
               index_t intermediate_size,
               bool has_zp
    )
    {
        _Pragma("clang diagnostic push") _Pragma("clang diagnostic ignored \"-Wc++20-extensions\"");

        static_assert(Block_K0_Group > 0, "Block_K0_Group must be greater than 0");
        static_assert(Block_K1_Group > 0, "Block_K1_Group must be greater than 0");

        index_t hidden_size_packed =  hidden_size / Problem::PackFactor;
        index_t hidden_size_group = hidden_size / QuantBlockSizeK_;
        index_t intermediate_size_packed = intermediate_size / Problem::PackFactor;
        index_t intermediate_size_group = intermediate_size / QuantBlockSizeK_;

        CK_TILE_LDS_ADDR ADataType* smem_0 = reinterpret_cast<CK_TILE_LDS_ADDR ADataType*>(smem);

        auto g_view = g_window_.get_bottom_tensor_view();
        auto g_scale_view = g_scale_window_.get_bottom_tensor_view();

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

                const GDataType* u_ptr = g_ptr + intermediate_size * hidden_size_packed;

                const auto u_view_ = make_naive_tensor_view<address_space_enum::global>(
                    u_ptr,
                    make_tuple(Block_N0, hidden_size_packed),
                    make_tuple(hidden_size_packed, 1),
                    number<kAlignmentG>{},      //for 16x64x64: 8
                    number<1>{});

                const auto u_view_1_ = pad_tensor_view(
                    u_view_,
                    make_tuple(number<Block_N0>{}, number<Block_K0_P>{}),
                    sequence<PadIntermediateSize, PadHiddenSize>{});
                return u_view_1_;
            }
        }();

        auto u_scale_view = [&]() {
            if constexpr(IsGateOnly)
            {
                static_assert(false, "GateOnly is not supported yet!");
                return g_scale_view;
            }
            else
            {
                const GScaleDataType* g_scale_ptr = g_scale_window_.get_bottom_tensor_view().get_buffer_view().p_data_;
                const GScaleDataType* u_scale_ptr = g_scale_ptr + intermediate_size * hidden_size_group;

                const auto u_scale_view_ = make_naive_tensor_view<address_space_enum::global>(
                        u_scale_ptr,
                        make_tuple(Block_N0, hidden_size_group),
                        make_tuple(hidden_size_group, number<1>{}),
                        number<1>{},            // scale alignment
                        number<1>{});
                return u_scale_view_;
            }
        }();

        const GZeroPointDataType* g_zero_point_ptr = nullptr;
        const GZeroPointDataType* u_zero_point_ptr = nullptr;
        const DZeroPointDataType* d_zero_point_ptr = nullptr;
        if (has_zp) {
            g_zero_point_ptr = g_zp_window_.get_bottom_tensor_view().get_buffer_view().p_data_;
            u_zero_point_ptr = g_zero_point_ptr + hidden_size_group *  intermediate_size_packed;
            d_zero_point_ptr = d_zp_window_.get_bottom_tensor_view().get_buffer_view().p_data_;
        }

        // 1. Gemm0 A
        // 1.1 A dram
        auto a_copy_dram_window = make_tile_window(
            a_window_.get_bottom_tensor_view(),
            make_tuple(number<Block_M0>{}, number<Block_K0>{}),
            a_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_A<Problem>());
        
        // 1.2 A lds written from dram
        constexpr auto a_copy_lds_block_desc = Policy::template MakeLdsStoreDesc_A<Problem>();
        constexpr auto a_lds_space_size      = ck_tile::integer_least_multiple(
            Policy::template GetSmemSize_A<Problem>(), Block_K0);
        // constexpr auto a_lds_bufs_elem_offset = 0;
        auto a_copy_lds_window0 = make_tile_window(
            make_tensor_view<address_space_enum::lds>(smem_0, a_copy_lds_block_desc),
            make_tuple(number<Block_M0>{}, number<Block_K0>{}),
            {0, 0});
        auto a_copy_lds_window1 = make_tile_window(
            make_tensor_view<address_space_enum::lds>(smem_0 + a_lds_space_size,
                                                      a_copy_lds_block_desc),
            make_tuple(number<Block_M0>{}, number<Block_K0>{}),
            {0, 0});
        auto a_copy_lds_windows = make_tuple(a_copy_lds_window0, a_copy_lds_window1);

        // 1.3 gemm0 A lds to quant
        auto quant_in_window0 = [&]() {
            const auto tmp_ = make_naive_tensor_view<address_space_enum::lds>(
                static_cast<const ADataType*>(smem_0),
                make_tuple(number<Block_M0>{}, number<Block_K0>{}),
                make_tuple(number<Block_K0>{}, 1),
                number<QT_Vector_N_>{},
                number<1>{});

            const auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), sequence<QT_kPadM, QT_kPadN>{});
            return make_tile_window(
                tmp2_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), {0, 0});
        }();

        auto quant_in_window1 = [&]() {
            const auto tmp_ = make_naive_tensor_view<address_space_enum::lds>(
                static_cast<const ADataType*>(smem_0 + a_lds_space_size),
                make_tuple(number<Block_M0>{}, number<Block_K0>{}),
                make_tuple(number<Block_K0>{}, 1),
                number<QT_Vector_N_>{},
                number<1>{});

            const auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), sequence<QT_kPadM, QT_kPadN>{});
            return make_tile_window(
                tmp2_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), {0, 0});
        }();

        // gemm0 A quant_out_window0
        CK_TILE_LDS_ADDR AQuantDataType* smem_quant0 = reinterpret_cast<CK_TILE_LDS_ADDR AQuantDataType*>(smem_quant);
        // CK_TILE_LDS_ADDR AQuantDataType* smem_quant1 = smem_quant0 + GetSmemSize_quant_out();

        auto make_gemm0_A_quant_out_tensor_view = [&](CK_TILE_LDS_ADDR AQuantDataType* smem_ptr) {
            return make_naive_tensor_view<address_space_enum::lds>(
                smem_ptr,
                make_tuple(number<Block_M0>{}, number<Block_K0>{}),
                make_tuple(number<Block_K0>{}, 1),
                number<QT_Vector_N_>{},
                number<1>{});
        };
        auto make_gemm0_A_quant_out_window = [&](CK_TILE_LDS_ADDR AQuantDataType* smem_ptr) {
            auto tmp_ = make_gemm0_A_quant_out_tensor_view(smem_ptr);
            auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), sequence<QT_kPadM, QT_kPadN>{});
            return make_tile_window(tmp2_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), {0, 0});
        };
        auto quant_out_window0 = make_gemm0_A_quant_out_window(smem_quant0);
        // auto quant_out_window1 = make_gemm0_A_quant_out_window(smem_quant1);

        // scale_out_window0
        CK_TILE_LDS_ADDR AScaleDataType* smem_scale0 = reinterpret_cast<CK_TILE_LDS_ADDR AScaleDataType*>(smem_scale);
        // CK_TILE_LDS_ADDR AScaleDataType* smem_scale1 = smem_scale0 + GetSmemSize_scale_out();
        auto make_gemm0_A_scale_out_window = [&](CK_TILE_LDS_ADDR AScaleDataType* smem_ptr) {
            const auto tmp_ = make_naive_tensor_view<address_space_enum::lds>(
                static_cast<AScaleDataType*>(smem_ptr),
                make_tuple(number<Block_M0 * QuantLoop_0>{}),
                make_tuple(1),
                number<1>{});
            const auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0 * QuantLoop_0>{}), sequence<QT_kPadM>{});
            return make_tile_window(tmp2_, make_tuple(number<Block_M0>{}), {0});
        };
        auto scale_out_window0 = make_gemm0_A_scale_out_window(smem_scale0);
        // auto scale_out_window1 = make_gemm0_A_scale_out_window(smem_scale1);

        // 1.4 gemm1 A lds to quant
        auto make_gemm1_A_quant_out_tensor_view = [&](CK_TILE_LDS_ADDR AQuantDataType* smem_ptr) {
            return make_naive_tensor_view<address_space_enum::lds>(
                smem_ptr,
                make_tuple(number<Block_M0>{}, number<Block_K1>{}),
                make_tuple(number<Block_K1>{}, 1),
                number<QT_Vector_N_>{},
                number<1>{});
        };
        auto make_gemm1_A_quant_out_window = [&](CK_TILE_LDS_ADDR AQuantDataType* smem_ptr) {
            auto tmp_ = make_gemm1_A_quant_out_tensor_view(smem_ptr);
            auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), sequence<QT_kPadM, QT_kPadN>{});
            return make_tile_window(tmp2_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), {0, 0});
        };
        auto make_gemm1_A_scale_out_window = [&](CK_TILE_LDS_ADDR AScaleDataType* smem_ptr) {
            const auto tmp_ = make_naive_tensor_view<address_space_enum::lds>(
                static_cast<AScaleDataType*>(smem_ptr),
                make_tuple(number<Block_M0 * QuantLoop_1>{}),
                make_tuple(1),
                number<1>{});
            const auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0 * QuantLoop_1>{}), sequence<QT_kPadM>{});
            return make_tile_window(tmp2_, make_tuple(number<Block_M0>{}), {0});
        };
        CK_TILE_LDS_ADDR AQuantDataType* smem_quant2 = reinterpret_cast<CK_TILE_LDS_ADDR AQuantDataType*>(smem_quant);
        CK_TILE_LDS_ADDR AScaleDataType* smem_scale2 = reinterpret_cast<CK_TILE_LDS_ADDR AScaleDataType*>(smem_scale);
        auto quant_out_bdg_win = make_gemm1_A_quant_out_window(smem_quant2);
        auto scale_out_bdg_win = make_gemm1_A_scale_out_window(smem_scale2);

        // 1.5 read quant out A from lds to register
        using WarpGemm0  = decltype(Policy::template GetWarpGemm0<Problem>());
        auto warp_gemm_0 = WarpGemm0{};
        constexpr auto a_gemm_sld_block_desc = Policy::template MakeLdsLoadDesc_A<Problem>();
        auto make_gemm0_a_window = [&](CK_TILE_LDS_ADDR AQuantDataType* smem_ptr) {
            auto a_gemm_sld_block = make_tensor_view<address_space_enum::lds>(smem_ptr, a_gemm_sld_block_desc);
            return make_tile_window(
                a_gemm_sld_block,
                a_gemm_sld_block_desc.get_lengths(),
                {0, 0},
                make_static_tile_distribution(typename WarpGemm0::AWarpDstrEncoding{}));
        };
        auto a_sld_win0 = make_gemm0_a_window(smem_quant0);
        // auto a_sld_win1 = make_gemm0_a_window(smem_quant1);



        // gate load from global to vgpr then to lds components
        auto g_copy_dram_window = make_tile_window(
            g_window_.get_bottom_tensor_view(), // [hidden_states, moe_intermediate_size]
            make_tuple(number<Block_N0>{},
                       number<Block_K0_P>{}),
            g_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_w4a8_G<Problem>());

        auto u_copy_dram_window = make_tile_window(
            u_view,
            make_tuple(number<Block_N0>{}, number<Block_K0_P>{}),
            {0, 0},
            Policy::template MakeGlobalTileDistribution_w4a8_G<Problem>());

        auto g_scale_copy_dram_window = make_tile_window(
            g_scale_window_.get_bottom_tensor_view(),
            make_tuple(number<Block_N0>{}, number<Block_K0_Group>{}),
            g_scale_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_w4a8_G_SC<Problem>());

        auto u_scale_copy_dram_window = make_tile_window(
            u_scale_view,
            make_tuple(number<Block_N0>{}, number<Block_K0_Group>{}),
            {0, 0},
            Policy::template MakeGlobalTileDistribution_w4a8_G_SC<Problem>());

        const GScaleDataType* g_scale_ptr = g_scale_copy_dram_window.get_bottom_tensor_view().get_buffer_view().p_data_;
        const GScaleDataType* u_scale_ptr = u_scale_copy_dram_window.get_bottom_tensor_view().get_buffer_view().p_data_;
        const DScaleDataType* d_scale_ptr = d_scale_window_.get_bottom_tensor_view().get_buffer_view().p_data_;


        // weight
        auto d_copy_dram_window = make_tile_window(
            d_window_.get_bottom_tensor_view(), // [hidden_states, moe_intermediate_size]
            make_tuple(number<Block_N1>{}, number<Block_K1_P>{}),
            d_window_.get_window_origin(),
            Policy::template MakeGlobalTileDistribution_w4a8_D<Problem>());


        using WarpGemm1  = decltype(Policy::template GetWarpGemm1<Problem>());
        auto warp_gemm_1 = WarpGemm1{};

        constexpr index_t atomic_issues = BlockShape::Block_M1 / number<4>{};
        auto o_windows                  = generate_tuple(
            [&](auto i) {
                return make_tile_window(o_window_[i],
                                        Policy::template MakeGlobalTileDistribution_O<Problem>());
            },
            number<atomic_issues>{});

        // 4. bridge
        // 4.1 gemm0 reduce acc store to lds
        auto bridge_sst_win = [&]() {
            const auto tmp_ = make_naive_tensor_view<address_space_enum::lds>(
                static_cast<ADataType*>(smem),
                make_tuple(number<Block_M0>{}, number<Block_N0>{}),
                make_tuple(number<Block_N0>{}, 1),
                number<Problem::BridgeSmemStoreVectorLength>{},
                number<1>{});
            return make_tile_window(
                tmp_, make_tuple(number<Block_M0>{}, number<Block_N0>{}), {0, 0});

        }();

        auto quant_in_bdg_win = [&]() {
            const auto tmp_ = make_naive_tensor_view<address_space_enum::lds>(
                static_cast<const ADataType*>(smem),
                make_tuple(number<Block_M0>{}, number<Block_N0>{}),
                make_tuple(number<Block_N0>{}, 1),
                number<QT_Vector_N_>{},
                number<1>{});

            const auto tmp2_ = pad_tensor_view(
                tmp_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), sequence<QT_kPadM, QT_kPadN>{});
            return make_tile_window(
                tmp2_, make_tuple(number<Block_M0>{}, number<QuantBlockSizeK_>{}), {0, 0});
        }();

        // 4.3 gemm1 load input a from lds
        auto gemm1_a_win = [&]() {
            return make_tile_window(make_naive_tensor_view<address_space_enum::lds>(
                                        static_cast<const DDataType*>(smem_quant2),
                                        make_tuple(number<Block_M0>{}, number<Block_N0>{}),
                                        make_tuple(number<Block_N0>{}, 1),
                                        number<Problem::BridgeSmemStoreVectorLength>{},     // 1
                                        number<1>{}),
                                    make_tuple(number<Block_M0>{}, number<Block_N0>{}),
                                    {0, 0},
                                    Policy::template MakeYTileDistribution<Problem>());
        }();


        // constexpr auto issues_a = number<a_copy_dram_window.get_num_of_access()>{};
        constexpr auto issues_g = number<g_copy_dram_window.get_num_of_access()>{};
        // constexpr auto issues_d = number<d_copy_dram_window.get_num_of_access()>{};

        const index_t num_blocks_k0 =
            (hidden_size + Block_K0 - 1) / Block_K0;
        const index_t num_blocks_n1 =
            (hidden_size + Block_N1 - 1) / Block_N1;

        using a_thread_type = decltype(load_tile(a_sld_win0));
        using g_thread_type = decltype(load_tile(g_copy_dram_window));
        using d_thread_type = decltype(load_tile(d_copy_dram_window));
        // using sld_d_thread_type = decltype(load_tile(d_sld_win));
        statically_indexed_array<a_thread_type, 1> gemm0_a_r;
        statically_indexed_array<g_thread_type, 2> gemm0_g_r;
        statically_indexed_array<g_thread_type, 2> gemm0_u_r;
        statically_indexed_array<d_thread_type, 2> gemm1_d_r;


        constexpr index_t thread_buf_size_gu = gemm0_g_r[I0].get_thread_buffer_size();
        constexpr index_t thread_buf_size_d = gemm1_d_r[I0].get_thread_buffer_size();

        auto g_regs  = Policy::template MakeBBlockTile_Gemm0<Problem>();     // coreponding to gate weights
        auto u_regs  = Policy::template MakeBBlockTile_Gemm0<Problem>();     // coreponding to up weights
        auto d_regs  = Policy::template MakeBBlockTile_Gemm1<Problem>();     // coreponding to down weights

        auto gld_a_init = [&]() { a_copy_dram_window.init_raw(); };

        auto gld_a = [&](auto& a_store_) {
            async_load_tile_by_inline_asm(a_store_, a_copy_dram_window);
        };
        auto move_a = [&]() {
            move_tile_window(a_copy_dram_window, {number<0>{}, number<Block_K0>{}});
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
            move_tile_window(g_copy_dram_window, {number<0>{}, number<Block_K0_P>{}});
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
                move_tile_window(g_copy_dram_window, {number<0>{}, number<Block_K0_P>{}});
            }
            else
            {
                move_tile_window(u_copy_dram_window, {number<0>{}, number<Block_K0_P>{}});
            }
        };

        auto gld_gu_scale_init = [&]() {
            g_scale_copy_dram_window.init_raw();
            u_scale_copy_dram_window.init_raw();
        };

        auto move_g_scale     = [&]() {
            move_tile_window(g_scale_copy_dram_window, {number<0>{}, number<Block_K0_Group>{}});
        };

        auto move_u_scale     = [&]() {
            move_tile_window(u_scale_copy_dram_window, {number<0>{}, number<Block_K0_Group>{}});
        };

        (void)move_u_scale;
        (void)move_g_scale;


        // statically_indexed_array<d_thread_type, 2> ds;
        auto gld_d_init = [&]() { d_copy_dram_window.init_raw(); };
        auto gld_d      = [&](auto& d_1) { load_tile(d_1, d_copy_dram_window); };
        auto move_d     = [&]() {
            // d move along gemm-n
            move_tile_window(d_copy_dram_window, {number<Block_N1>{}, number<0>{}});
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
                move_tile_window(o_windows[i], {number<0>{}, number<Block_N1>{}});
            });
        };

        // 3. Gemm0 scale. Fow this pipeline, we only support Block_K0 = QuantBlockSizeK_
        auto acc_0 = make_tuple(Policy::template MakeCBlockTile_Gemm0<Problem>(),
                                Policy::template MakeCBlockTile_Gemm0<Problem>());
        auto acc_0_dequant = make_tuple(make_static_distributed_tensor<float>(acc_0[I0].get_tile_distribution()),
                                        make_static_distributed_tensor<float>(acc_0[I1].get_tile_distribution()));

        auto acc_1s = generate_tuple(
            [&](auto) { return Policy::template MakeCBlockTile_Gemm1<Problem>(); }, number<2>{});
        auto acc_1s_dequant = generate_tuple([&](auto) { return make_static_distributed_tensor<ODataType>(acc_1s[I0].get_tile_distribution()); }, number<2>{});

        constexpr index_t thread_buf_size_acc0 = acc_0[I0].get_thread_buffer_size();
        constexpr index_t thread_buf_size_acc1s = acc_1s[I0].get_thread_buffer_size();

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

        index_t loop_index = 0;

        auto pipeline_gemm0 = [&]() {
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);      //wait for a_sld_win0
            __builtin_amdgcn_sched_barrier(0);
            quantize_a_0(quant_in_window0, quant_out_window0, scale_out_window0, smem_quant_inter);
            sld_a(gemm0_a_r[I0], a_sld_win0);
            gld_a(a_copy_lds_windows(I1));

            // pre-load a and next u/g
            __builtin_amdgcn_sched_barrier(0);
            // __builtin_amdgcn_s_setprio(1);

            move_a();
            gld_g(gemm0_g_r[I1]);
            move_g();
            gld_u(gemm0_u_r[I1]);
            move_u();

            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);

            // first mmac group
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_g_r[I0], g_regs, g_zero_point_ptr, loop_index, hidden_size_group);
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_u_r[I0], u_regs, u_zero_point_ptr, loop_index, hidden_size_group);
            gemm_0(acc_0[I0], gemm0_a_r[I0], g_regs);
            gemm_0(acc_0[I1], gemm0_a_r[I0], u_regs);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I0], acc_0_dequant[I0], smem_scale0, g_scale_ptr, hidden_size_group, loop_index);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I1], acc_0_dequant[I1], smem_scale0, u_scale_ptr, hidden_size_group, loop_index);
            loop_index++;


            // second mmac group
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);    //wait for a_sld_win1
            // __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            quantize_a_0(quant_in_window1, quant_out_window0, scale_out_window0, smem_quant_inter);
            sld_a(gemm0_a_r[I0], a_sld_win0);
            gld_a(a_copy_lds_windows(I0));
            __builtin_amdgcn_sched_barrier(0);

            move_a();
            gld_g(gemm0_g_r[I0]);
            move_g();
            gld_u(gemm0_u_r[I0]);
            move_u();
            __builtin_amdgcn_s_setprio(1);

            
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_g_r[I1], g_regs, g_zero_point_ptr, loop_index, hidden_size_group);
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_u_r[I1], u_regs, u_zero_point_ptr, loop_index, hidden_size_group);
            gemm_0(acc_0[I0], gemm0_a_r[I0], g_regs);
            gemm_0(acc_0[I1], gemm0_a_r[I0], u_regs);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I0], acc_0_dequant[I0], smem_scale0, g_scale_ptr, hidden_size_group, loop_index);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I1], acc_0_dequant[I1], smem_scale0, u_scale_ptr, hidden_size_group, loop_index);
            loop_index++;
        };

        auto pipeline_gemm0_tail = [&]() {
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);  //wait for a_sld_win0
            // __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            quantize_a_0(quant_in_window0, quant_out_window0, scale_out_window0, smem_quant_inter);
            sld_a(gemm0_a_r[I0], a_sld_win0);
            gld_a(a_copy_lds_windows(I1));
            __builtin_amdgcn_sched_barrier(0);
            gld_g(gemm0_g_r[I1]);
            gld_u(gemm0_u_r[I1]);

            // pre-load gemm0_a_r and next u/g
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);

            // first mmac group
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_g_r[I0], g_regs, g_zero_point_ptr, loop_index, hidden_size_group);
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_u_r[I0], u_regs, u_zero_point_ptr, loop_index, hidden_size_group);
            gemm_0(acc_0[I0], gemm0_a_r[I0], g_regs);
            gemm_0(acc_0[I1], gemm0_a_r[I0], u_regs);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I0], acc_0_dequant[I0], smem_scale0, g_scale_ptr, hidden_size_group, loop_index);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I1], acc_0_dequant[I1], smem_scale0, u_scale_ptr, hidden_size_group, loop_index);
            loop_index++;

            // second mmac group
            __builtin_amdgcn_s_setprio(0);
            block_sync_load_raw(2 * issues_g);
            // __builtin_amdgcn_s_barrier();
            __builtin_amdgcn_sched_barrier(0);
            quantize_a_0(quant_in_window1, quant_out_window0, scale_out_window0, smem_quant_inter);
            sld_a(gemm0_a_r[I0], a_sld_win0);

            // block_sync_load_raw(issues_a + 2 * issues_g);
            __builtin_amdgcn_s_setprio(1);
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_g_r[I1], g_regs, g_zero_point_ptr, loop_index, hidden_size_group);
            prepare_gemm0_B<thread_buf_size_gu>(gemm0_u_r[I1], u_regs, u_zero_point_ptr, loop_index, hidden_size_group);
            gemm_0(acc_0[I0], gemm0_a_r[I0], g_regs);
            gemm_0(acc_0[I1], gemm0_a_r[I0], u_regs);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I0], acc_0_dequant[I0], smem_scale0, g_scale_ptr, hidden_size_group, loop_index);
            dequantize_acc0<thread_buf_size_acc0>(acc_0[I1], acc_0_dequant[I1], smem_scale0, u_scale_ptr, hidden_size_group, loop_index);

            __builtin_amdgcn_sched_barrier(0);
        };

        auto gemm1_a_r  = Policy::template MakeGemm1ABlockTile<Problem>();

        auto pipeline_bridge = [&]() {
            // using WarpGemm  = remove_cvref_t<decltype(warp_gemm_0)>;
            // using CDataType = typename WarpGemm::CDataType;
            if constexpr(IsGateOnly)
            {
                static_assert(false, "not supported yet");
            }
            else
            {
                block_sync_lds(); // ensure last input load have been read from lds
                sweep_tile(
                    acc_0_dequant.at(number<0>{}),
                    [&](auto idx0, auto idx1) {
                        fp32x2_t v_{acc_0_dequant.at(number<0>{})(idx0), acc_0_dequant.at(number<0>{})(idx1)};
                        typename Problem::GateActivation{}(v_, v_);
                        acc_0_dequant.at(number<0>{})(idx0) = v_.x;
                        acc_0_dequant.at(number<0>{})(idx1) = v_.y;
                    },
                    sequence<1, 2>{}); // m=1, n=4 continuos element in thread_buffer(VGPR)
                // mul
                auto reduce_acc_0 =
                    tile_elementwise_in([&](const auto& a_, const auto& b_) { return a_ * b_; },
                                        acc_0_dequant.at(number<0>{}),
                                        acc_0_dequant.at(number<1>{}));

                constexpr auto bridge_tile_enc =
                    Policy::template MakeBridgeTileDistribution<Problem>();

                auto bridge_tile_tensor =
                    make_static_distributed_tensor<float>(bridge_tile_enc);
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

                store_tile(bridge_sst_win, cast_tile<YDataType, false>(bridge_tile_tensor));
                clear_tile(acc_1s(I0));
                block_sync_lds();
                
                quantize_a_1(quant_in_bdg_win, quant_out_bdg_win, scale_out_bdg_win, smem_quant_inter);
                
                load_tile(gemm1_a_r, gemm1_a_win);
                clear_tile(acc_1s(I1));
                // block_sync_lds();
                __builtin_amdgcn_sched_barrier(0);
            }
        };

        // note, gemm-1 start from idx-1 to N-2 (0, 1, 2....N-1)
        auto pipeline_gemm1 = [&]() {
            // block_sync_load_raw(issues_d);
            gld_d(gemm1_d_r[I1]);
            move_d();
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);
            prepare_gemm1_B<thread_buf_size_d>(gemm1_d_r[I0], d_regs, d_zero_point_ptr, loop_index, intermediate_size_group);
            gemm_1(acc_1s[I0], gemm1_a_r,  d_regs);
            dequantize_acc1s<thread_buf_size_acc1s>(acc_1s[I0], acc_1s_dequant[I0], smem_scale2, d_scale_ptr, intermediate_size_group, loop_index);
            loop_index++;
            atomic_add_o(acc_1s_dequant[I0]);
            asm volatile("s_waitcnt vmcnt(0)");
            // block_sync_lds();
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(0);

            // Note: if support pk_atomic_add, here will use 2interleave and f16 atomic
            // move_o();
            // block_sync_load_raw(issues_d);
            gld_d(gemm1_d_r[I0]);
            move_d();
            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);

            prepare_gemm1_B<thread_buf_size_d>(gemm1_d_r[I1], d_regs, d_zero_point_ptr, loop_index, intermediate_size_group);
            gemm_1(acc_1s[I1], gemm1_a_r, d_regs);
            dequantize_acc1s<thread_buf_size_acc1s>(acc_1s[I1], acc_1s_dequant[I1], smem_scale2, d_scale_ptr, intermediate_size_group, loop_index);
            loop_index++;
            atomic_add_o(acc_1s_dequant[I1]);
            asm volatile("s_waitcnt vmcnt(0)");

            __builtin_amdgcn_s_setprio(0);

            clear_tile(acc_1s(I0));
            clear_tile(acc_1s(I1));
            // block_sync_lds();
            // asm volatile("s_waitcnt vmcnt(0)");
            __builtin_amdgcn_sched_barrier(0);
        };

        auto pipeline_gemm1_head = [&]() {
            gld_d_init();
            gld_d(gemm1_d_r[I0]);
            move_d();
        };
        auto pipeline_gemm1_tail = [&]() {
            // block_sync_load_raw(issues_d);
            gld_d(gemm1_d_r[I1]);
            move_d();

            __builtin_amdgcn_sched_barrier(0);
            __builtin_amdgcn_s_setprio(1);
            prepare_gemm1_B<thread_buf_size_d>(gemm1_d_r[I0], d_regs, d_zero_point_ptr, loop_index, intermediate_size_group);
            gemm_1(acc_1s[I0], gemm1_a_r, d_regs);
            dequantize_acc1s<thread_buf_size_acc1s>(acc_1s[I0], acc_1s_dequant[I0], smem_scale2, d_scale_ptr, intermediate_size_group, loop_index);
            loop_index++;
            atomic_add_o(acc_1s_dequant[I0]);
            // block_sync_lds();
            asm volatile("s_waitcnt vmcnt(0)");

            __builtin_amdgcn_sched_barrier(0);
            // block_sync_load_raw(issues_d);
            prepare_gemm1_B<thread_buf_size_d>(gemm1_d_r[I1], d_regs, d_zero_point_ptr, loop_index, intermediate_size_group);
            gemm_1(acc_1s[I1], gemm1_a_r, d_regs);
            dequantize_acc1s<thread_buf_size_acc1s>(acc_1s[I1], acc_1s_dequant[I1], smem_scale2, d_scale_ptr, intermediate_size_group, loop_index);
            atomic_add_o(acc_1s_dequant[I1]);
            asm volatile("s_waitcnt vmcnt(0)");

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
        gld_g(gemm0_g_r[I0]);
        move_g();
        gld_u(gemm0_u_r[I0]);
        move_u();

        gld_gu_scale_init();

        clear_tile(acc_0.at(I0));
        clear_tile(acc_0.at(I1));
        clear_tile(acc_0_dequant.at(I0));
        clear_tile(acc_0_dequant.at(I1));


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

        loop_index = 0;

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
