// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <string>

#include "ck_tile/core.hpp"
#include "ck_tile/host.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv.hpp"
#include "ck_tile/ops/fused_conv/kernel/fused_conv_host_args.hpp"
#include "ck_tile/ops/fused_conv/utility/fused_conv_mode.hpp"

namespace ck_tile {

template <typename TilePartitioner_,
          typename IgemmPipeline_,
          typename EpiloguePipeline_,
          ConvFwdSpec ConvSpec_,
          FusedConvMode FuseMode_>
struct FusedConvWaspKernelV2R1
{
    using TilePartitioner  = remove_cvref_t<TilePartitioner_>;
    using IgemmPipeline    = remove_cvref_t<IgemmPipeline_>;
    using EpiloguePipeline = remove_cvref_t<EpiloguePipeline_>;

    using Policy = remove_cvref_t<typename IgemmPipeline::Policy>;

    static constexpr index_t NDimSpatial = IgemmPipeline::NDimSpatial;

    static constexpr index_t BlockSize = IgemmPipeline::BlockSize;

    static constexpr index_t InVecLen  = IgemmPipeline::InVecLen;
    static constexpr index_t WeiVecLen = IgemmPipeline::WeiVecLen;
    static constexpr index_t OutVecLen = IgemmPipeline::OutVecLen;

    static constexpr auto ConvSpec = ConvSpec_;
    static constexpr auto FuseMode = FuseMode_;

    using Problem = remove_cvref_t<typename IgemmPipeline::Problem>;

    using InLayout  = remove_cvref_t<typename Problem::InLayout>;
    using WeiLayout = remove_cvref_t<typename Problem::WeiLayout>;
    using OutLayout = remove_cvref_t<typename Problem::OutLayout>;

    using InDataType   = remove_cvref_t<typename Problem::InDataType>;
    using WeiDataType  = remove_cvref_t<typename Problem::WeiDataType>;
    using OutDataType  = remove_cvref_t<typename Problem::OutDataType>;
    using BiasDataType = remove_cvref_t<typename Problem::BiasDataType>;

    using InElementwiseOp  = remove_cvref_t<typename Problem::InElementwiseOp>;
    using WeiElementwiseOp = remove_cvref_t<typename Problem::WeiElementwiseOp>;
    using OutElementwiseOp = remove_cvref_t<typename Problem::OutElementwiseOp>;

    using HostArgs = FusedConvHostArgs<NDimSpatial>;

    using BlockwiseGemm = decltype(Policy::template GetBlockwiseGemm<Problem>());

    using WarpGemm = typename BlockwiseGemm::WarpGemm;

    static constexpr index_t NDim = HostArgs::NDim;

    static constexpr index_t MPerWG    = Problem::MPerWG;
    static constexpr index_t NPerWG    = Problem::NPerWG;
    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t NumPrefetch = Problem::NumPrefetch;

    static constexpr auto transformer =
        ConvFwdToGemmTransformer<NDimSpatial, InVecLen, WeiVecLen, OutVecLen, ConvSpec>{};

    // do not pad K here
    static constexpr auto padder = MatrixPadder_v2<true, true, false, index_t, index_t, index_t>{
        MPerBlock, NPerBlock, KPerBlock};

    static constexpr auto I0 = number<0>{};
    static constexpr auto I1 = number<1>{};

    static constexpr auto FilterLen    = ConvSpec == ConvFwdSpec::Filter3x3 ? 3 : 1;
    static constexpr auto FilterWindow = sequence<FilterLen, FilterLen>{};

    CK_TILE_HOST static auto MakeInDescriptor(const HostArgs& args)
    {
        // TODO: make sure naive tensor is in n,h,w,c format
        const auto in_gemmmraw_gemmkraw_desc =
            transformer.template MakeADescriptor_M_K<InLayout>(args.input.lengths,
                                                               args.input.strides,
                                                               args.weight.lengths,
                                                               args.weight.strides,
                                                               args.output.lengths,
                                                               args.output.strides,
                                                               args.conv_filter_strides,
                                                               args.conv_filter_dilations,
                                                               args.input_left_pads,
                                                               args.input_right_pads);

        const auto in_gemmm_gemmk_desc = padder.PadADescriptor_M_K(in_gemmmraw_gemmkraw_desc);

        return in_gemmm_gemmk_desc;
    }

    CK_TILE_HOST static auto MakeWeiDescriptor(const HostArgs& args)
    {
        const auto wei_gemmnraw_gemmkraw_desc = transformer.template MakeBDescriptor_N_K<WeiLayout>(
            args.weight.lengths, args.weight.strides);

        const auto wei_gemmn_gemmk_desc = padder.PadBDescriptor_N_K(wei_gemmnraw_gemmkraw_desc);

        return wei_gemmn_gemmk_desc;
    }

    CK_TILE_HOST static auto MakeOutDescriptor(const HostArgs& args)
    {
        const auto out_gemmmraw_gemmnraw_desc = transformer.template MakeCDescriptor_M_N<OutLayout>(
            args.output.lengths, args.output.strides);

        const auto out_gemmm_gemmn_desc = padder.PadCDescriptor_M_N(out_gemmmraw_gemmnraw_desc);

        return out_gemmm_gemmn_desc;
    }

    CK_TILE_HOST static auto MakeBiasDescriptor(const HostArgs& args)
    {
        const auto out_gemmmraw_gemmnraw_desc = transformer.template MakeCDescriptor_M_N<OutLayout>(
            args.output.lengths, args.output.strides);

        const auto bias_gemmmraw_gemmnraw_desc =
            make_naive_tensor_descriptor(make_tuple(out_gemmmraw_gemmnraw_desc.get_length(I0),
                                                    out_gemmmraw_gemmnraw_desc.get_length(I1)),
                                         make_tuple(I0, I1),
                                         number<OutVecLen>{},
                                         I1);

        const auto bias_gemmm_gemmn_desc = padder.PadCDescriptor_M_N(bias_gemmmraw_gemmnraw_desc);

        return bias_gemmm_gemmn_desc;
    }

    using InDesc   = decltype(MakeInDescriptor({}));
    using WeiDesc  = decltype(MakeWeiDescriptor({}));
    using OutDesc  = decltype(MakeOutDescriptor({}));
    using BiasDesc = decltype(MakeBiasDescriptor({}));

    struct KernelArgs
    {
        const InDataType* in_ptr;
        const WeiDataType* wei_ptr;
        OutDataType* out_ptr;
        const BiasDataType* bias_ptr;
        const OutDataType* res_ptr;

        index_t num_group;

        InDesc in_desc;
        WeiDesc wei_desc;
        OutDesc out_desc;
        BiasDesc bias_desc;
        OutDesc res_desc;

        InElementwiseOp in_element_op;
        WeiElementwiseOp wei_element_op;
        OutElementwiseOp out_element_op;

        // const_stride for cache swizzle
        index_t in_const_stride;
        index_t wei_const_stride;
        index_t out_const_stride;

        TilePartitioner tile_partitioner;
    };

    CK_TILE_HOST static constexpr auto
    MakeHostArgs(const void* input_ptr_,
                 const void* weight_ptr_,
                 void* output_ptr_,
                 const void* bias_ptr_,
                 const void* res_ptr_,
                 const std::array<index_t, NDim>& in_g_n_c_wis_lengths,
                 const std::array<index_t, NDim>& in_g_n_c_wis_strides,
                 const std::array<index_t, NDim>& wei_g_k_c_xs_lengths,
                 const std::array<index_t, NDim>& wei_g_k_c_xs_strides,
                 const std::array<index_t, NDim>& out_g_n_k_wos_lengths,
                 const std::array<index_t, NDim>& out_g_n_k_wos_strides,
                 const std::array<index_t, NDimSpatial>& strides,
                 const std::array<index_t, NDimSpatial>& dilations,
                 const std::array<index_t, NDimSpatial>& left_pads,
                 const std::array<index_t, NDimSpatial>& right_pads)
    {
        return HostArgs(input_ptr_,
                        weight_ptr_,
                        output_ptr_,
                        bias_ptr_,
                        res_ptr_,
                        in_g_n_c_wis_lengths,
                        in_g_n_c_wis_strides,
                        wei_g_k_c_xs_lengths,
                        wei_g_k_c_xs_strides,
                        out_g_n_k_wos_lengths,
                        out_g_n_k_wos_strides,
                        strides,
                        dilations,
                        left_pads,
                        right_pads);
    }

    CK_TILE_HOST static constexpr auto MakeKernelArgs(const HostArgs& hargs)
    {
        namespace ctc = ck_tile::tensor_layout::convolution;

        const auto in_desc_b_m_k  = MakeInDescriptor(hargs);
        const auto wei_desc_b_n_k = MakeWeiDescriptor(hargs);
        const auto out_desc_m_n   = MakeOutDescriptor(hargs);
        const auto bias_desc_m_n  = MakeBiasDescriptor(hargs);
        const auto res_desc_m_n   = MakeOutDescriptor(hargs);

        const index_t num_group = hargs.input.lengths[0];

        // precompute const_stride for in/wei/out tensor
        const index_t in_const_stride =
            hargs.conv_filter_strides[1] * hargs.input.strides[4] * sizeof(InDataType);
        const index_t wei_const_stride = hargs.weight.strides[4] * sizeof(WeiDataType);
        const index_t out_const_stride = hargs.output.strides[4] * sizeof(OutDataType);

        return KernelArgs{static_cast<const InDataType*>(hargs.in_ptr),
                          static_cast<const WeiDataType*>(hargs.wei_ptr),
                          static_cast<OutDataType*>(hargs.out_ptr),
                          static_cast<const BiasDataType*>(hargs.bias_ptr),
                          static_cast<const OutDataType*>(hargs.res_ptr),
                          num_group,
                          in_desc_b_m_k,
                          wei_desc_b_n_k,
                          out_desc_m_n,
                          bias_desc_m_n,
                          res_desc_m_n,
                          InElementwiseOp{},
                          WeiElementwiseOp{},
                          OutElementwiseOp{},
                          in_const_stride,
                          wei_const_stride,
                          out_const_stride, // unused
                          {out_desc_m_n.get_length(I0), out_desc_m_n.get_length(I1), 1, 1, 1}};
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetNumLoop(const KernelArgs& kargs)
    {
        const auto gemm_k = kargs.wei_desc.get_length(number<1>{});

        return gemm_k / KPerBlock;
    }

    CK_TILE_HOST static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return IgemmPipeline::CalculateHasMainLoop(num_loop);
    }

    CK_TILE_HOST static bool IsSupportedArgument(const HostArgs& hargs, const KernelArgs& kargs)
    {
        namespace ctc = ck_tile::tensor_layout::convolution;

        // fuse mode check
        if constexpr(!((FuseMode >= FusedConvMode::Conv) &&
                       (FuseMode <= FusedConvMode::ConvBiasResRelu)))
        {
            return false;
        }

        // TODO: support more dtype
        if constexpr(!(std::is_same_v<InDataType, ck_tile::fp16_t> &&
                       std::is_same_v<WeiDataType, ck_tile::fp16_t>))
        {
            return false;
        }

        // this version use special load pattern, only k32/k64 is supported
        if constexpr((KPerBlock != 32) && (KPerBlock != 64))
        {
            return false;
        }

        // this version use special load pattern based on buffer_load_dwordx4 lds
        if constexpr((Problem::InGmemLoadVecLen * sizeof(InDataType) != 16) ||
                     (Problem::WeiGmemLoadVecLen * sizeof(WeiDataType) != 16))
        {
            return false;
        }

        // this version use ds_read_b128 to resolve bank conflict with special load pattern
        if constexpr((Problem::InSmemLoadStoreVecLen * sizeof(InDataType) != 16) ||
                     (Problem::WeiSmemLoadStoreVecLen * sizeof(WeiDataType) != 16))
        {
            return false;
        }

        // only support i32/f32 as AccDataType
        if constexpr(!(std::is_same_v<typename Problem::AccDataType, float> ||
                       std::is_same_v<typename Problem::AccDataType, int32_t>))
        {
            return false;
        }

        if constexpr(std::is_same_v<InLayout, ctc::NHWGC> &&
                     std::is_same_v<WeiLayout, ctc::GKYXC> && std::is_same_v<OutLayout, ctc::NHWGK>)
        {
            const index_t in_channels  = hargs.weight.lengths[2];
            const index_t out_channels = hargs.weight.lengths[1];

            if(!((in_channels % Problem::InGmemLoadVecLen == 0) &&
                 (in_channels % Problem::WeiGmemLoadVecLen == 0) &&
                 (out_channels % Problem::OutGmemStoreVecLen == 0)))
            {
                return false;
            }
        }
        else if constexpr(std::is_base_of_v<ctc::BaseNGCHWc, InLayout> &&
                          std::is_base_of_v<ctc::BaseGKCYXc, WeiLayout> &&
                          std::is_base_of_v<ctc::BaseNGCHWc, OutLayout>)
        {
            if(!((InLayout::x % Problem::InGmemLoadVecLen == 0) &&
                 (WeiLayout::x % Problem::WeiGmemLoadVecLen == 0) &&
                 (OutLayout::x % Problem::OutGmemStoreVecLen == 0)))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // device check
        const auto target_enum = ck_tile::get_hcu_target_enum();

        // buffer_load_dwordx4 lds impls, gfx928 is not supported
        if(target_enum < hcu_target_enum::gfx936)
        {
            return false;
        }

        // conv spec check, only support f1x1 & f3x3
        if constexpr(ConvSpec == ConvFwdSpec::Filter1x1Stride1Pad0)
        {
            if(!(hargs.weight.lengths[3] == 1 && hargs.weight.lengths[4] == 1 &&
                 hargs.conv_filter_strides[0] == 1 && hargs.conv_filter_strides[1] == 1 &&
                 hargs.input_left_pads[0] == 0 && hargs.input_left_pads[1] == 0 &&
                 hargs.input_right_pads[0] == 0 && hargs.input_right_pads[1] == 0))
            {
                return false;
            }
        }
        else if constexpr(ConvSpec == ConvFwdSpec::Filter1x1Pad0)
        {
            if(!(hargs.weight.lengths[3] == 1 && hargs.weight.lengths[4] == 1 &&
                 hargs.conv_filter_strides[0] != 1 && hargs.conv_filter_strides[1] != 1 &&
                 hargs.input_left_pads[0] == 0 && hargs.input_left_pads[1] == 0 &&
                 hargs.input_right_pads[0] == 0 && hargs.input_right_pads[1] == 0))
            {
                return false;
            }
        }
        else if constexpr(ConvSpec == ConvFwdSpec::Filter3x3)
        {
            // FIXME: 3x3 not ready for (2, 1), waiting for compiler fix
            if constexpr(Problem::MWGs == 2 && Problem::NWGs == 1)
            {
                return false;
            }

            if(!(hargs.weight.lengths[3] == 3 && hargs.weight.lengths[4] == 3))
            {
                return false;
            }
        }
        else
        {
            return false;
        }

        // TODO: support grouped fused conv
        if(kargs.num_group != 1)
        {
            return false;
        }

        // cache swizzle only support 64 * (2^n) as const_stride
        if(!(ck_tile::ispow2(kargs.in_const_stride) && ck_tile::ispow2(kargs.wei_const_stride)))
        {
            return false;
        }

        // TODO: support dilation
        if(!(hargs.conv_filter_dilations[0] == 1 && hargs.conv_filter_dilations[1] == 1))
        {
            return false;
        }

        // gemm compatability check
        const auto gemm_m = kargs.out_desc.get_length(number<0>{});
        const auto gemm_n = kargs.out_desc.get_length(number<1>{});
        const auto gemm_k = kargs.wei_desc.get_length(number<1>{});

        if(!((gemm_m % MPerBlock == 0) && (gemm_n % NPerBlock == 0) && (gemm_k % KPerBlock == 0)))
        {
            return false;
        }

        const auto num_loop = GetNumLoop(kargs);

        if(!IgemmPipeline::IsSupported(num_loop))
        {
            return false;
        }

        return true;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return max(IgemmPipeline::GetLdsByteSize(), EpiloguePipeline::GetLdsByteSize());
    }

    template <bool HasHotLoop>
    CK_TILE_DEVICE void operator()(KernelArgs kargs, bool_constant<HasHotLoop> has_hot_loop) const
    {
        // TODO: support grouped conv
        auto in_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.in_ptr, kargs.in_desc, kargs.in_const_stride);
        auto wei_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.wei_ptr, kargs.wei_desc, kargs.wei_const_stride);

        auto out_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.out_ptr, kargs.out_desc);
        auto bias_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.bias_ptr, kargs.bias_desc);
        auto res_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.res_ptr, kargs.res_desc);

        // allocate LDS
        __shared__ char p_smem[GetLdsByteSize()];

        // block work idx
        const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(get_block_1d_id());

        const index_t block_work_idx_m =
            __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
        const index_t block_work_idx_n =
            __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);

        index_t num_loop = __builtin_amdgcn_readfirstlane(GetNumLoop(kargs));

        // A matrix in LDS
        constexpr auto in_gemm_lds_block_desc = Policy::template MakeInLdsGemmBlockDesc<Problem>();
        constexpr auto in_lds_elem_size       = Policy::template GetInLdsElemSize<Problem>();

        // B matrix in LDS
        constexpr auto wei_gemm_lds_block_desc =
            Policy::template MakeWeiLdsGemmBlockDesc<Problem>();
        constexpr auto wei_lds_elem_size = Policy::template GetWeiLdsElemSize<Problem>();

        if(get_sub_warpgroup_id(Problem::SubWGSize) == 0)
        {
            auto in_copy_dram_window =
                make_tile_window_conv_fwd_activation_async<lds_layout_traits<KPerBlock>::value>(
                    in_tensor_view,
                    make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                    {block_work_idx_m, 0},
                    FilterWindow,
                    Policy::template MakeInDramTileDstr<Problem>(),
                    InLayout{},
                    number<KPerBlock>{});

            auto wei_copy_dram_window =
                make_tile_window_conv_fwd_filter_async<lds_layout_traits<KPerBlock>::value>(
                    wei_tensor_view,
                    make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                    {block_work_idx_n, 0},
                    FilterWindow,
                    Policy::template MakeWeiDramTileDstr<Problem>(),
                    WeiLayout{},
                    number<KPerBlock>{});

            constexpr auto in_lds_buf_elem_offset = 0;
            constexpr auto wei_lds_buf_elem_offset =
                NumPrefetch * Policy::template GetInLdsElemSize<Problem>();

            auto in_gemm_lds_windows = lds_utils::AllocateLdsWindows<InDataType, NumPrefetch>(
                p_smem,
                in_lds_elem_size,
                in_lds_buf_elem_offset,
                KPerBlock,
                make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                make_multi_index(0, 0),
                in_gemm_lds_block_desc);

            auto wei_gemm_lds_windows = lds_utils::AllocateLdsWindows<WeiDataType, NumPrefetch>(
                p_smem,
                wei_lds_elem_size,
                wei_lds_buf_elem_offset,
                KPerBlock,
                make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                make_multi_index(0, 0),
                wei_gemm_lds_block_desc);

            // wasp gemm pipeline
            const auto acc_block_tensor = IgemmPipeline{}(in_copy_dram_window,
                                                          in_gemm_lds_windows,
                                                          kargs.in_element_op,
                                                          wei_copy_dram_window,
                                                          wei_gemm_lds_windows,
                                                          kargs.wei_element_op,
                                                          num_loop,
                                                          has_hot_loop);
            // wasp epilogue pipeline
            auto out_dram_window = make_tile_window(out_tensor_view,
                                                    EpiloguePipeline::GetTileLengths(),
                                                    {block_work_idx_m, block_work_idx_n});

            auto bias_dram_window = make_tile_window(bias_tensor_view,
                                                     EpiloguePipeline::GetTileLengths(),
                                                     {block_work_idx_m, block_work_idx_n});

            auto res_dram_window = make_tile_window(res_tensor_view,
                                                    EpiloguePipeline::GetTileLengths(),
                                                    {block_work_idx_m, block_work_idx_n});

            if constexpr(FuseMode == FusedConvMode::ConvBias ||
                         FuseMode == FusedConvMode::ConvBiasRelu)
            {
                EpiloguePipeline{}(out_dram_window,
                                   bias_dram_window,
                                   acc_block_tensor,
                                   kargs.out_element_op,
                                   p_smem,
                                   0);
            }
            else if constexpr(FuseMode == FusedConvMode::ConvBiasResRelu)
            {
                EpiloguePipeline{}(out_dram_window,
                                   bias_dram_window,
                                   res_dram_window,
                                   acc_block_tensor,
                                   kargs.out_element_op,
                                   p_smem,
                                   0);
            }
            else if constexpr(FuseMode == FusedConvMode::Conv)
            {
                EpiloguePipeline{}(out_dram_window,
                                   acc_block_tensor,
                                   kargs.out_element_op,
                                   p_smem,
                                   0);
            }
            else
            {
                static_assert(false, "Not implemented");
            }
        }
        else if(get_sub_warpgroup_id(Problem::SubWGSize) == 1)
        {
            const index_t smem_elem_offset = __builtin_amdgcn_readfirstlane(
                EpiloguePipeline::MakeLdsDesc().get_element_space_size());

            if constexpr(Problem::MWGs == 2 && Problem::NWGs == 1)
            {
                auto in_copy_dram_window =
                    make_tile_window(in_tensor_view,
                                     make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                                     {block_work_idx_m + MPerWG, 0});

                const index_t warp_id_m =
                    ck_tile::get_sub_warp_id(Problem::SubWGSize) / BlockwiseGemm::NWarpsPerWG;

                auto in_warp_dram_windows = generate_tuple(
                    [&](auto i) {
                        return make_tile_window_conv_fwd_activation_opt(
                            in_copy_dram_window.get_bottom_tensor_view(),
                            make_tuple(number<WarpGemm::kM>{}, number<WarpGemm::kK>{}),
                            in_copy_dram_window.get_window_origin() +
                                multi_index<2>{warp_id_m * WarpGemm::kM +
                                                   i * BlockwiseGemm::MPerBlockPerIter,
                                               0},
                            FilterWindow,
                            make_static_tile_distribution(typename WarpGemm::AWarpDstrEncoding{}),
                            typename Problem::InLayout{},
                            number<KPerBlock>{});
                    },
                    number<BlockwiseGemm::MWarpIterPerWG>{});

                // wei lds: shared
                constexpr auto wei_lds_buf_elem_offset =
                    NumPrefetch * Policy::template GetInLdsElemSize<Problem>();

                auto wei_gemm_lds_windows = lds_utils::AllocateLdsWindows<WeiDataType, NumPrefetch>(
                    p_smem,
                    wei_lds_elem_size,
                    wei_lds_buf_elem_offset,
                    KPerBlock,
                    make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    wei_gemm_lds_block_desc);

                // wasp gemm pipeline
                const auto acc_block_tensor = IgemmPipeline{}(in_warp_dram_windows,
                                                              kargs.in_element_op,
                                                              wei_gemm_lds_windows,
                                                              num_loop,
                                                              has_hot_loop);

                // wasp epilogue pipeline
                auto out_dram_window =
                    make_tile_window(out_tensor_view,
                                     EpiloguePipeline::GetTileLengths(),
                                     {block_work_idx_m + MPerWG, block_work_idx_n});

                auto bias_dram_window =
                    make_tile_window(bias_tensor_view,
                                     EpiloguePipeline::GetTileLengths(),
                                     {block_work_idx_m + MPerWG, block_work_idx_n});

                auto res_dram_window =
                    make_tile_window(res_tensor_view,
                                     EpiloguePipeline::GetTileLengths(),
                                     {block_work_idx_m + MPerWG, block_work_idx_n});

                if constexpr(FuseMode == FusedConvMode::ConvBias ||
                             FuseMode == FusedConvMode::ConvBiasRelu)
                {
                    EpiloguePipeline{}(out_dram_window,
                                       bias_dram_window,
                                       acc_block_tensor,
                                       kargs.out_element_op,
                                       p_smem,
                                       smem_elem_offset);
                }
                else if constexpr(FuseMode == FusedConvMode::ConvBiasResRelu)
                {
                    EpiloguePipeline{}(out_dram_window,
                                       bias_dram_window,
                                       res_dram_window,
                                       acc_block_tensor,
                                       kargs.out_element_op,
                                       p_smem,
                                       smem_elem_offset);
                }
                else if constexpr(FuseMode == FusedConvMode::Conv)
                {
                    EpiloguePipeline{}(out_dram_window,
                                       acc_block_tensor,
                                       kargs.out_element_op,
                                       p_smem,
                                       smem_elem_offset);
                }
                else
                {
                    static_assert(false, "Not implemented");
                }
            }
            else if constexpr(Problem::MWGs == 1 && Problem::NWGs == 2)
            {
                auto wei_copy_dram_window =
                    make_tile_window(wei_tensor_view,
                                     make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                                     {block_work_idx_n + NPerWG, 0});

                const index_t warp_id_n =
                    ck_tile::get_sub_warp_id(Problem::SubWGSize) % BlockwiseGemm::NWarpsPerWG;

                auto wei_warp_dram_windows = generate_tuple(
                    [&](auto i) {
                        return make_tile_window_conv_fwd_filter_opt(
                            wei_copy_dram_window.get_bottom_tensor_view(),
                            make_tuple(number<WarpGemm::kN>{}, number<WarpGemm::kK>{}),
                            wei_copy_dram_window.get_window_origin() +
                                multi_index<2>{warp_id_n * WarpGemm::kN +
                                                   i * BlockwiseGemm::NPerBlockPerIter,
                                               0},
                            FilterWindow,
                            make_static_tile_distribution(typename WarpGemm::BWarpDstrEncoding{}),
                            typename Problem::WeiLayout{},
                            number<KPerBlock>{});
                    },
                    number<BlockwiseGemm::NWarpIterPerWG>{});

                // in lds: shared
                constexpr auto in_lds_buf_elem_offset = 0;

                auto in_gemm_lds_windows = lds_utils::AllocateLdsWindows<WeiDataType, NumPrefetch>(
                    p_smem,
                    in_lds_elem_size,
                    in_lds_buf_elem_offset,
                    KPerBlock,
                    make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    in_gemm_lds_block_desc);

                // wasp gemm pipeline
                const auto acc_block_tensor = IgemmPipeline{}(in_gemm_lds_windows,
                                                              wei_warp_dram_windows,
                                                              kargs.wei_element_op,
                                                              num_loop,
                                                              has_hot_loop);

                // wasp epilogue pipeline
                auto out_dram_window =
                    make_tile_window(out_tensor_view,
                                     EpiloguePipeline::GetTileLengths(),
                                     {block_work_idx_m, block_work_idx_n + NPerWG});

                auto bias_dram_window =
                    make_tile_window(bias_tensor_view,
                                     EpiloguePipeline::GetTileLengths(),
                                     {block_work_idx_m, block_work_idx_n + NPerWG});

                auto res_dram_window =
                    make_tile_window(res_tensor_view,
                                     EpiloguePipeline::GetTileLengths(),
                                     {block_work_idx_m, block_work_idx_n + NPerWG});

                if constexpr(FuseMode == FusedConvMode::ConvBias ||
                             FuseMode == FusedConvMode::ConvBiasRelu)
                {
                    EpiloguePipeline{}(out_dram_window,
                                       bias_dram_window,
                                       acc_block_tensor,
                                       kargs.out_element_op,
                                       p_smem,
                                       smem_elem_offset);
                }
                else if constexpr(FuseMode == FusedConvMode::ConvBiasResRelu)
                {
                    EpiloguePipeline{}(out_dram_window,
                                       bias_dram_window,
                                       res_dram_window,
                                       acc_block_tensor,
                                       kargs.out_element_op,
                                       p_smem,
                                       smem_elem_offset);
                }
                else if constexpr(FuseMode == FusedConvMode::Conv)
                {
                    EpiloguePipeline{}(out_dram_window,
                                       acc_block_tensor,
                                       kargs.out_element_op,
                                       p_smem,
                                       smem_elem_offset);
                }
                else
                {
                    static_assert(false, "Not implemented");
                }
            }
            else
            {
                static_assert(false, "Invalid WG organization");
            }
        }
    }
};

} // namespace ck_tile
