// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <algorithm>
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
          ConvFwdSpecEnum ConvSpec_,
          FusedConvMode FuseMode_>
struct FusedConvMlsKernelV1
{
    using TilePartitioner = remove_cvref_t<TilePartitioner_>;
    using IgemmPipeline   = remove_cvref_t<IgemmPipeline_>;

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

    static constexpr index_t NDim = HostArgs::NDim;

    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t NumLdsStages = Problem::NumLdsStages;

    static constexpr auto InMlsWindowLengths  = sequence<Problem::MPerTls, Problem::KPerTls>{};
    static constexpr auto WeiMlsWindowLengths = sequence<Problem::NPerTls, Problem::KPerTls>{};

    static constexpr auto transformer =
        ConvFwdToGemmTransformerV2<NDimSpatial,
                                   sequence<MPerBlock, NPerBlock, KPerBlock>,
                                   sequence<InVecLen, WeiVecLen, OutVecLen>,
                                   ConvSpec>{};

    static constexpr auto I0 = number<0>{};
    static constexpr auto I1 = number<1>{};

    using WaspHelper = wasp_helper<Problem::NumWarps, Problem::BlockSize, false>;

    CK_TILE_HOST static auto MakeInDescriptor(const HostArgs& args)
    {
        // TODO: make sure naive tensor is in n,h,w,c format
        return transformer.template MakeADescriptor_M_K<tensor_layout::gemm::RowMajor>(
            args.input.lengths,
            args.input.strides,
            args.weight.lengths,
            args.weight.strides,
            args.output.lengths,
            args.output.strides,
            args.conv_filter_strides,
            args.conv_filter_dilations,
            args.input_left_pads,
            args.input_right_pads);
    }

    CK_TILE_HOST static auto MakeWeiDescriptor(const HostArgs& args)
    {
        return transformer.template MakeBDescriptor_N_K<tensor_layout::gemm::RowMajor>(
            args.weight.lengths, args.weight.strides);
    }

    CK_TILE_HOST static auto MakeOutDescriptor(const HostArgs& args)
    {
        return transformer.template MakeCDescriptor_M_N<tensor_layout::gemm::RowMajor>(
            args.output.lengths, args.output.strides);
    }

    CK_TILE_HOST static auto MakeBiasDescriptor(const HostArgs& args)
    {
        const auto out_gemmmraw_gemmnraw_desc = transformer.template MakeCDescriptor_M_N<OutLayout>(
            args.output.lengths, args.output.strides);

        return make_naive_tensor_descriptor(make_tuple(out_gemmmraw_gemmnraw_desc.get_length(I0),
                                                       out_gemmmraw_gemmnraw_desc.get_length(I1)),
                                            make_tuple(I0, I1),
                                            number<OutVecLen>{},
                                            I1);
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
        index_t lda;
        index_t ldb;
        index_t k_remainder;

        InDesc in_desc;
        WeiDesc wei_desc;
        OutDesc out_desc;
        BiasDesc bias_desc;
        OutDesc res_desc;

        InElementwiseOp in_element_op;
        WeiElementwiseOp wei_element_op;
        OutElementwiseOp out_element_op;

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

        const index_t lda = hargs.input.strides[4];
        const index_t ldb = hargs.weight.strides[1];
        const index_t k_remainder =
            in_desc_b_m_k.get_lengths()[number<1>{}] - hargs.weight.lengths[2];
        const index_t num_group = hargs.input.lengths[0];

        return KernelArgs{static_cast<const InDataType*>(hargs.in_ptr),
                          static_cast<const WeiDataType*>(hargs.wei_ptr),
                          static_cast<OutDataType*>(hargs.out_ptr),
                          static_cast<const BiasDataType*>(hargs.bias_ptr),
                          static_cast<const OutDataType*>(hargs.res_ptr),
                          num_group,
                          lda,
                          ldb,
                          k_remainder,
                          in_desc_b_m_k,
                          wei_desc_b_n_k,
                          out_desc_m_n,
                          bias_desc_m_n,
                          res_desc_m_n,
                          InElementwiseOp{},
                          WeiElementwiseOp{},
                          OutElementwiseOp{},
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
        if constexpr(FuseMode != FusedConvMode::Conv)
        {
            return false;
        }

        // TODO: support more dtype
        if constexpr(!(std::is_same_v<InDataType, ck_tile::fp16_t> &&
                       std::is_same_v<WeiDataType, ck_tile::fp16_t>))
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
            const index_t out_channels = hargs.weight.lengths[1];

            if(!(out_channels % Problem::OutGmemStoreVecLen == 0))
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

        // need tls support
        if(target_enum < hcu_target_enum::gfx938)
        {
            return false;
        }

        // only support f1x1s1p0 conv
        if(ConvSpec != ConvFwdSpecEnum::F1x1_S1_D1_P0)
        {
            return false;
        }

        if(!IsApplicableConvProblem<ConvSpec>(hargs))
        {
            return false;
        }

        if(kargs.num_group != 1)
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
        return IgemmPipeline::GetLdsByteSize();
    }

    template <bool HasHotLoop>
    CK_TILE_DEVICE void operator()(KernelArgs kargs, bool_constant<HasHotLoop> has_hot_loop) const
    {
        // TODO: support grouped conv
        auto in_tensor_view =
            make_hcu_tensor_view<address_space_enum::global>(kargs.in_ptr, kargs.in_desc);
        auto wei_tensor_view =
            make_hcu_tensor_view<address_space_enum::global>(kargs.wei_ptr, kargs.wei_desc);
        auto out_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.out_ptr, kargs.out_desc);

        // allocate LDS
        __shared__ char p_smem[GetLdsByteSize()];

        // block work idx
        const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(get_block_1d_id());

        const index_t block_work_idx_m =
            __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
        const index_t block_work_idx_n =
            __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);

        index_t num_loop = GetNumLoop(kargs);

        // A matrix in LDS
        constexpr auto in_gemm_lds_block_desc = Policy::template MakeInLdsGemmBlockDesc<Problem>();
        constexpr auto in_lds_elem_size       = Policy::template GetInLdsElemSize<Problem>();

        // B matrix in LDS
        constexpr auto wei_gemm_lds_block_desc =
            Policy::template MakeWeiLdsGemmBlockDesc<Problem>();
        constexpr auto wei_lds_elem_size = Policy::template GetWeiLdsElemSize<Problem>();

        auto in_mls_window =
            make_tile_window_mls(in_tensor_view,
                                 sequence<number<MPerBlock>{}, number<KPerBlock>{}>{},
                                 InMlsWindowLengths,
                                 {block_work_idx_m, 0},
                                 tensor_layout::gemm::RowMajor{},
                                 number<Problem::MmmacInterleave>{},
                                 WaspHelper{},
                                 kargs.lda,
                                 kargs.k_remainder);

        auto wei_mls_window =
            make_tile_window_mls(wei_tensor_view,
                                 sequence<number<NPerBlock>{}, number<KPerBlock>{}>{},
                                 WeiMlsWindowLengths,
                                 {block_work_idx_n, 0},
                                 tensor_layout::gemm::RowMajor{},
                                 number<Problem::NmmacInterleave>{},
                                 WaspHelper{},
                                 kargs.ldb,
                                 kargs.k_remainder);

        constexpr auto in_lds_buf_elem_offset = 0;
        constexpr auto wei_lds_buf_elem_offset =
            NumLdsStages * Policy::template GetInLdsElemSize<Problem>();

        auto in_lds_windows = lds_utils::AllocateLdsWindows<InDataType, NumLdsStages>(
            p_smem,
            in_lds_elem_size,
            in_lds_buf_elem_offset,
            KPerBlock,
            make_tuple(number<MPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0),
            in_gemm_lds_block_desc);

        auto wei_lds_windows = lds_utils::AllocateLdsWindows<WeiDataType, NumLdsStages>(
            p_smem,
            wei_lds_elem_size,
            wei_lds_buf_elem_offset,
            KPerBlock,
            make_tuple(number<NPerBlock>{}, number<KPerBlock>{}),
            make_multi_index(0, 0),
            wei_gemm_lds_block_desc);

        // wasp gemm pipeline
        const auto acc_block_tensor = IgemmPipeline{}(in_mls_window,
                                                      in_lds_windows,
                                                      kargs.in_element_op,
                                                      wei_mls_window,
                                                      wei_lds_windows,
                                                      kargs.wei_element_op,
                                                      num_loop,
                                                      has_hot_loop);
        // wasp epilogue pipeline
        auto out_dram_window =
            make_tile_window(out_tensor_view,
                             make_tuple(number<MPerBlock>{}, number<NPerBlock>{}),
                             {block_work_idx_m, block_work_idx_n});

        store_tile(out_dram_window, cast_tile<OutDataType>(acc_block_tensor));
    }
};

} // namespace ck_tile
