// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <string>

#include "ck_tile/core.hpp"
#include "ck_tile/host.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv.hpp"
#include "ck_tile/ops/conv3d/utility/conv3d_fwd_spec.hpp"
#include "ck_tile/ops/conv3d/utility/conv3d_fwd_to_gemm_transformer.hpp"

namespace ck_tile {

template <typename TilePartitioner_,
          typename IgemmPipeline_,
          typename EpiloguePipeline_,
          Conv3dFwdSpec ConvSpec_>
struct Conv3dFwdWaspKernelV1
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

    static_assert(OutVecLen == 1);

    static constexpr auto ConvSpec = ConvSpec_;

    using Problem = remove_cvref_t<typename IgemmPipeline::Problem>;

    using InLayout  = remove_cvref_t<typename Problem::InLayout>;
    using WeiLayout = remove_cvref_t<typename Problem::WeiLayout>;
    using OutLayout = remove_cvref_t<typename Problem::OutLayout>;

    using InDataType   = remove_cvref_t<typename Problem::InDataType>;
    using WeiDataType  = remove_cvref_t<typename Problem::WeiDataType>;
    using OutDataType  = remove_cvref_t<typename Problem::OutDataType>;

    using InElementwiseOp  = remove_cvref_t<typename Problem::InElementwiseOp>;
    using WeiElementwiseOp = remove_cvref_t<typename Problem::WeiElementwiseOp>;
    using OutElementwiseOp = remove_cvref_t<typename Problem::OutElementwiseOp>;

    using HostArgs = ConvFwdHostArgs<NDimSpatial>;

    static constexpr index_t NDim = HostArgs::NDim;

    static constexpr index_t MPerWG    = Problem::MPerWG;
    static constexpr index_t NPerWG    = Problem::NPerWG;
    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr auto transformer =
        Conv3dFwdToGemmTransformer<NDimSpatial, InVecLen, WeiVecLen, OutVecLen, ConvSpec>{};

    // do not pad K here
    static constexpr auto padder = MatrixPadder_v2<true, true, true, index_t, index_t, index_t>{
        MPerBlock, NPerBlock, KPerBlock};

    static constexpr auto I0 = number<0>{};
    static constexpr auto I1 = number<1>{};

    CK_TILE_HOST static auto MakeInDescriptor(const HostArgs& args)
    {
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
        const auto gemm_m              = in_gemmm_gemmk_desc.get_length(I0);
        const auto gemm_k              = in_gemmm_gemmk_desc.get_length(I1);

        const auto in_b_gemmm_gemmk_desc =
            transform_tensor_descriptor(in_gemmm_gemmk_desc,
                                        make_tuple(make_pass_through_transform(gemm_m),
                                                   make_unmerge_transform(make_tuple(I1, gemm_k))),
                                        make_tuple(sequence<0>{}, sequence<1>{}),
                                        make_tuple(sequence<1>{}, sequence<0, 2>{}));

        return in_b_gemmm_gemmk_desc;
    }

    CK_TILE_HOST static auto MakeWeiDescriptor(const HostArgs& args)
    {
        const auto wei_gemmnraw_gemmkraw_desc = transformer.template MakeBDescriptor_N_K<WeiLayout>(
            args.weight.lengths, args.weight.strides);

        const auto wei_gemmn_gemmk_desc = padder.PadBDescriptor_N_K(wei_gemmnraw_gemmkraw_desc);
        const auto gemm_n               = wei_gemmn_gemmk_desc.get_length(I0);
        const auto gemm_k               = wei_gemmn_gemmk_desc.get_length(I1);

        const auto wei_b_gemmn_gemmk_desc =
            transform_tensor_descriptor(wei_gemmn_gemmk_desc,
                                        make_tuple(make_pass_through_transform(gemm_n),
                                                   make_unmerge_transform(make_tuple(I1, gemm_k))),
                                        make_tuple(sequence<0>{}, sequence<1>{}),
                                        make_tuple(sequence<1>{}, sequence<0, 2>{}));

        return wei_b_gemmn_gemmk_desc;
    }

    CK_TILE_HOST static auto MakeOutDescriptor(const HostArgs& args)
    {
        const auto out_gemmmraw_gemmnraw_desc = transformer.template MakeCDescriptor_M_N<OutLayout>(
            args.output.lengths, args.output.strides);

        const auto out_gemmm_gemmn_desc = padder.PadCDescriptor_M_N(out_gemmmraw_gemmnraw_desc);

        return out_gemmm_gemmn_desc;
    }

    using InDesc  = decltype(MakeInDescriptor({}));
    using WeiDesc = decltype(MakeWeiDescriptor({}));
    using OutDesc = decltype(MakeOutDescriptor({}));

    struct KernelArgs
    {
        const InDataType* in_ptr;
        const WeiDataType* wei_ptr;
        OutDataType* out_ptr;

        index_t num_group;

        InDesc in_desc;
        WeiDesc wei_desc;
        OutDesc out_desc;

        InElementwiseOp in_element_op;
        WeiElementwiseOp wei_element_op;
        OutElementwiseOp out_element_op;

        TilePartitioner tile_partitioner;
        GroupedConvPtrOffset grouped_conv_ptr_offset;
    };

    CK_TILE_HOST static constexpr auto
    MakeHostArgs(const void* input_ptr_,
                 const void* weight_ptr_,
                 void* output_ptr_,
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

        const index_t num_group = hargs.input.lengths[0];

        return KernelArgs{
            static_cast<const InDataType*>(hargs.input_ptr),
            static_cast<const WeiDataType*>(hargs.weight_ptr),
            static_cast<OutDataType*>(hargs.output_ptr),
            num_group,
            in_desc_b_m_k,
            wei_desc_b_n_k,
            out_desc_m_n,
            InElementwiseOp{},
            WeiElementwiseOp{},
            OutElementwiseOp{},
            {out_desc_m_n.get_length(I0), out_desc_m_n.get_length(I1), 1, 1, 1},
            {hargs.input.strides[0], hargs.weight.strides[0], hargs.output.strides[0]}};
    }

    CK_TILE_HOST static constexpr index_t GetNumLoop(const KernelArgs& kargs)
    {
        const auto gemm_k = kargs.wei_desc.get_length(number<2>{});

        return gemm_k / KPerBlock;
    }

    CK_TILE_HOST static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return IgemmPipeline::CalculateHasMainLoop(num_loop);
    }

    CK_TILE_HOST static bool IsSupportedArgument(const HostArgs& hargs, const KernelArgs& kargs)
    {
        namespace ctc = ck_tile::tensor_layout::convolution;

        // only support i32/f32 as AccDataType
        if constexpr(!(std::is_same_v<typename Problem::AccDataType, float> ||
                       std::is_same_v<typename Problem::AccDataType, int32_t>))
        {
            return false;
        }

        if constexpr(std::is_same_v<InLayout, ctc::NDHWGC> &&
                     std::is_same_v<WeiLayout, ctc::GKZYXC> &&
                     std::is_same_v<OutLayout, ctc::NDHWGK>)
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
        else
        {
            return false;
        }

        // device check
        const auto target_enum = ck_tile::get_hcu_target_enum();

        if(target_enum < hcu_target_enum::gfx928)
        {
            return false;
        }

        // TODO: support more dtype
        if constexpr(!((std::is_same_v<InDataType, ck_tile::fp16_t> &&
                        std::is_same_v<WeiDataType, ck_tile::fp16_t>) ||
                       (std::is_same_v<InDataType, ck_tile::bf16_t> &&
                        std::is_same_v<WeiDataType, ck_tile::bf16_t>)))
        {
            return false;
        }

        if constexpr(ConvSpec == Conv3dFwdSpec::Filter1x1x1Stride1Pad0)
        {
            if(!(hargs.weight.lengths[3] == 1 && hargs.weight.lengths[4] == 1 &&
                 hargs.weight.lengths[5] == 1 && hargs.conv_filter_strides[0] == 1 &&
                 hargs.conv_filter_strides[1] == 1 && hargs.conv_filter_strides[2] == 1 &&
                 hargs.input_left_pads[0] == 0 && hargs.input_left_pads[1] == 0 &&
                 hargs.input_left_pads[2] == 0 && hargs.input_right_pads[0] == 0 &&
                 hargs.input_right_pads[1] == 0 && hargs.input_right_pads[2] == 0))
            {
                return false;
            }
        }
        else if constexpr(ConvSpec == Conv3dFwdSpec::Filter1x1x1Pad0)
        {
            if(!(hargs.weight.lengths[3] == 1 && hargs.weight.lengths[4] == 1 &&
                 hargs.weight.lengths[5] == 1 && hargs.conv_filter_strides[0] != 1 &&
                 hargs.conv_filter_strides[1] != 1 && hargs.conv_filter_strides[2] != 1 &&
                 hargs.input_left_pads[0] == 0 && hargs.input_left_pads[1] == 0 &&
                 hargs.input_left_pads[2] == 0 && hargs.input_right_pads[0] == 0 &&
                 hargs.input_right_pads[1] == 0 && hargs.input_right_pads[2] == 0))
            {
                return false;
            }
        }

        // gemm compatability check
        const auto gemm_m = kargs.out_desc.get_length(number<0>{});
        const auto gemm_n = kargs.out_desc.get_length(number<1>{});
        const auto gemm_k = kargs.wei_desc.get_length(number<2>{});

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
        // compute grouped conv ptr offset
        const index_t num_blocks_per_group =
            __builtin_amdgcn_readfirstlane(get_grid_size() / kargs.num_group);
        const index_t g_idx =
            __builtin_amdgcn_readfirstlane(get_block_1d_id() / num_blocks_per_group);

        const long_index_t in_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetAPtrOffset(g_idx)));
        const long_index_t wei_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetBPtrOffset(g_idx)));
        const long_index_t out_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetCPtrOffset(g_idx)));

        auto in_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.in_ptr + in_g_offset, kargs.in_desc);
        auto wei_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.wei_ptr + wei_g_offset, kargs.wei_desc);
        auto out_tensor_view = make_tensor_view<address_space_enum::global>(
            kargs.out_ptr + out_g_offset, kargs.out_desc);

        // allocate LDS
        __shared__ char p_smem[GetLdsByteSize()];

        // block work idx
        const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(get_block_1d_id());

        const index_t block_work_idx_m =
            __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
        const index_t block_work_idx_n =
            __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);

        index_t num_loop =
            __builtin_amdgcn_readfirstlane(kargs.in_desc.get_length(number<2>{}) / KPerBlock);

        // A matrix in LDS
        constexpr auto in_copy_lds_block_desc = Policy::template MakeInLdsCopyBlockDesc<Problem>();
        constexpr auto in_gemm_lds_block_desc = Policy::template MakeInLdsGemmBlockDesc<Problem>();
        constexpr auto in_lds_elem_size       = Policy::template GetInLdsElemSize<Problem>();

        // B matrix in LDS
        constexpr auto wei_copy_lds_block_desc =
            Policy::template MakeWeiLdsCopyBlockDesc<Problem>();
        constexpr auto wei_gemm_lds_block_desc =
            Policy::template MakeWeiLdsGemmBlockDesc<Problem>();
        constexpr auto wei_lds_elem_size = Policy::template GetWeiLdsElemSize<Problem>();

        if(get_sub_warpgroup_id(Problem::SubWGSize) == 0)
        {
            auto in_copy_dram_window =
                make_tile_window(in_tensor_view,
                                 make_tuple(number<1>{}, number<MPerWG>{}, number<KPerBlock>{}),
                                 {0, block_work_idx_m, 0},
                                 Policy::template MakeInDramTileDstr<Problem>(),
                                 number<1>{},
                                 bool_constant<true>{});

            auto wei_copy_dram_window =
                make_tile_window(wei_tensor_view,
                                 make_tuple(number<1>{}, number<NPerWG>{}, number<KPerBlock>{}),
                                 {0, block_work_idx_n, 0},
                                 Policy::template MakeWeiDramTileDstr<Problem>(),
                                 number<1>{},
                                 bool_constant<true>{});

            constexpr auto in_lds_buf_elem_offset  = 0;
            constexpr auto wei_lds_buf_elem_offset = Policy::template GetInLdsElemSize<Problem>();

            auto in_copy_lds_window = lds_utils::AllocateLdsWindows<InDataType, I1>(
                p_smem,
                in_lds_elem_size,
                in_lds_buf_elem_offset,
                KPerBlock,
                make_tuple(I1, number<MPerWG>{}, number<KPerBlock>{}),
                make_multi_index(0, 0, 0),
                in_copy_lds_block_desc,
                in_copy_dram_window.get_tile_distribution())(I0);

            auto wei_copy_lds_window = lds_utils::AllocateLdsWindows<WeiDataType, I1>(
                p_smem,
                wei_lds_elem_size,
                wei_lds_buf_elem_offset,
                KPerBlock,
                make_tuple(I1, number<NPerWG>{}, number<KPerBlock>{}),
                make_multi_index(0, 0, 0),
                wei_copy_lds_block_desc,
                wei_copy_dram_window.get_tile_distribution())(I0);

            auto in_gemm_lds_window = lds_utils::AllocateLdsWindows<InDataType, I1>(
                p_smem,
                in_lds_elem_size,
                in_lds_buf_elem_offset,
                KPerBlock,
                make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                make_multi_index(0, 0),
                in_gemm_lds_block_desc)(I0);

            auto wei_gemm_lds_window = lds_utils::AllocateLdsWindows<WeiDataType, I1>(
                p_smem,
                wei_lds_elem_size,
                wei_lds_buf_elem_offset,
                KPerBlock,
                make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                make_multi_index(0, 0),
                wei_gemm_lds_block_desc)(I0);

            // wasp gemm pipeline
            const auto acc_block_tensor = IgemmPipeline{}(in_copy_dram_window,
                                                          in_copy_lds_window,
                                                          in_gemm_lds_window,
                                                          kargs.in_element_op,
                                                          wei_copy_dram_window,
                                                          wei_copy_lds_window,
                                                          wei_gemm_lds_window,
                                                          kargs.wei_element_op,
                                                          num_loop,
                                                          has_hot_loop);
            // wasp epilogue pipeline
            auto out_dram_window = make_tile_window(out_tensor_view,
                                                    make_tuple(number<MPerWG>{}, number<NPerWG>{}),
                                                    {block_work_idx_m, block_work_idx_n});

            EpiloguePipeline{}(out_dram_window, acc_block_tensor);
        }
        else if(get_sub_warpgroup_id(Problem::SubWGSize) == 1)
        {
            if constexpr(Problem::MWGs == 2 && Problem::NWGs == 1)
            {
                auto in_copy_dram_window =
                    make_tile_window(in_tensor_view,
                                     make_tuple(number<1>{}, number<MPerWG>{}, number<KPerBlock>{}),
                                     {0, block_work_idx_m + MPerWG, 0},
                                     Policy::template MakeInDramTileDstr<Problem>(),
                                     number<1>{},
                                     bool_constant<true>{});

                // in lds: private
                constexpr auto in_lds_buf_elem_offset =
                    Policy::template GetInLdsElemSize<Problem>() +
                    Policy::template GetWeiLdsElemSize<Problem>();
                // wei lds: shared
                constexpr auto wei_lds_buf_elem_offset =
                    Policy::template GetInLdsElemSize<Problem>();

                auto in_copy_lds_window = lds_utils::AllocateLdsWindows<InDataType, I1>(
                    p_smem,
                    in_lds_elem_size,
                    in_lds_buf_elem_offset,
                    KPerBlock,
                    make_tuple(I1, number<MPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0, 0),
                    in_copy_lds_block_desc,
                    in_copy_dram_window.get_tile_distribution())(I0);

                auto in_gemm_lds_window = lds_utils::AllocateLdsWindows<InDataType, I1>(
                    p_smem,
                    in_lds_elem_size,
                    in_lds_buf_elem_offset,
                    KPerBlock,
                    make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    in_gemm_lds_block_desc)(I0);

                auto wei_gemm_lds_window = lds_utils::AllocateLdsWindows<WeiDataType, I1>(
                    p_smem,
                    wei_lds_elem_size,
                    wei_lds_buf_elem_offset,
                    KPerBlock,
                    make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    wei_gemm_lds_block_desc)(I0);

                // wasp gemm pipeline
                const auto acc_block_tensor = IgemmPipeline{}(in_copy_dram_window,
                                                              in_copy_lds_window,
                                                              in_gemm_lds_window,
                                                              kargs.in_element_op,
                                                              wei_gemm_lds_window,
                                                              num_loop,
                                                              has_hot_loop);

                // wasp epilogue pipeline
                auto out_dram_window =
                    make_tile_window(out_tensor_view,
                                     make_tuple(number<MPerWG>{}, number<NPerWG>{}),
                                     {block_work_idx_m + MPerWG, block_work_idx_n});

                EpiloguePipeline{}(out_dram_window, acc_block_tensor);
            }
            else
            {
                static_assert(false, "Invalid WG organization");
            }
        }
    }
};

} // namespace ck_tile
