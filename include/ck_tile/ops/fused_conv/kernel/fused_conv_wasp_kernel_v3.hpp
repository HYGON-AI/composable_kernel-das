// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include <algorithm>
#include <string>

#include "ck_tile/core.hpp"
#include "ck_tile/host.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv.hpp"
#include "ck_tile/ops/fused_conv/kernel/fused_conv_host_args.hpp"
#include "ck_tile/ops/fused_conv/utility/fused_conv_mode.hpp"
#include "ck_tile/ops/fused_conv/utility/grouped_fused_conv_ptr_offset.hpp"

namespace ck_tile {

template <typename TilePartitioner_, typename GemmPipeline_, typename EpiloguePipeline_>
struct FusedConvWaspKernelV3
{
    using TilePartitioner  = remove_cvref_t<TilePartitioner_>;
    using GemmPipeline     = remove_cvref_t<GemmPipeline_>;
    using EpiloguePipeline = remove_cvref_t<EpiloguePipeline_>;

    using Policy  = remove_cvref_t<typename GemmPipeline::Policy>;
    using Problem = remove_cvref_t<typename GemmPipeline::Problem>;

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

    using BlockGemm = decltype(Policy::template GetBlockwiseGemm<Problem>());

    static constexpr index_t NDimSpatial = Problem::NDimSpatial;

    using HostArgs = FusedConvHostArgs<NDimSpatial>;

    static constexpr index_t NDim = HostArgs::NDim;

    static constexpr auto ConvSpec      = Problem::ConvSpec;
    static constexpr auto FilterLengths = Problem::ConvFwdSpecDetail::FilterLengths;

    static constexpr index_t MPerWG    = Problem::MPerWG;
    static constexpr index_t NPerWG    = Problem::NPerWG;
    static constexpr index_t MPerBlock = Problem::MPerBlock;
    static constexpr index_t NPerBlock = Problem::NPerBlock;
    static constexpr index_t KPerBlock = Problem::KPerBlock;

    static constexpr index_t InVecLen  = Problem::InGmemLoadVecLen;
    static constexpr index_t WeiVecLen = Problem::WeiGmemLoadVecLen;
    static constexpr index_t OutVecLen = Problem::OutGmemStoreVecLen;

    static constexpr auto transformer =
        ConvFwdToGemmTransformerV2<NDimSpatial,
                                   sequence<MPerBlock, NPerBlock, KPerBlock>,
                                   sequence<InVecLen, WeiVecLen, OutVecLen>,
                                   ConvSpec>{};

    CK_TILE_HOST static auto MakeInDescriptor(const HostArgs& args)
    {
        return transformer.template MakeADescriptor_M_K<InLayout>(args.input.lengths,
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
        return transformer.template MakeBDescriptor_N_K<WeiLayout>(args.weight.lengths,
                                                                   args.weight.strides);
    }

    CK_TILE_HOST static auto MakeOutDescriptor(const HostArgs& args)
    {
        return transformer.template MakeCDescriptor_M_N<OutLayout>(args.output.lengths,
                                                                   args.output.strides);
    }

    CK_TILE_HOST static auto MakeBiasDescriptor(const HostArgs& args)
    {
        const auto out_gemmmraw_gemmnraw_desc = transformer.template MakeCDescriptor_M_N<OutLayout>(
            args.output.lengths, args.output.strides);

        return make_naive_tensor_descriptor(
            make_tuple(out_gemmmraw_gemmnraw_desc.get_length(number<0>{}),
                       out_gemmmraw_gemmnraw_desc.get_length(number<1>{})),
            make_tuple(number<0>{}, number<1>{}),
            number<OutVecLen>{},
            number<1>{});
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

        TilePartitioner tile_partitioner;
        fused_conv::GroupedConvPtrOffset grouped_conv_ptr_offset;
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

        return KernelArgs{
            static_cast<const InDataType*>(hargs.in_ptr),
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
            {out_desc_m_n.get_length(number<0>{}), out_desc_m_n.get_length(number<1>{}), 1, 1, 1},
            {hargs.input.strides[0],
             hargs.weight.strides[0],
             hargs.output.strides[0],
             hargs.weight.lengths[1]}};
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetNumLoop(const KernelArgs& kargs)
    {
        const auto gemm_k = kargs.wei_desc.get_length(number<1>{});

        return gemm_k / KPerBlock;
    }

    CK_TILE_HOST static constexpr bool CalculateHasMainLoop(index_t num_loop)
    {
        return GemmPipeline::CalculateHasMainLoop(num_loop);
    }

    CK_TILE_HOST static constexpr bool CalculateHasMainLoop(const KernelArgs& kargs)
    {
        return GemmPipeline::CalculateHasMainLoop(GetNumLoop(kargs));
    }

    CK_TILE_HOST static bool IsEfficientConfig(const HostArgs& hargs, const KernelArgs& kargs)
    {
        // Padding K is inefficient
        if(hargs.weight.lengths[1] / NPerBlock == 0)
        {
            return false;
        }

        // naive utilization check
        index_t num_cu        = get_num_cu();
        index_t num_tiles     = kargs.tile_partitioner.GetNumTiles();
        index_t partial_waves = num_tiles % num_cu;

        if(partial_waves > 0 && num_tiles > num_cu)
        {
            index_t full_waves = num_tiles / num_cu;
            float utilization =
                static_cast<float>(num_tiles) / static_cast<float>((full_waves + 1) * num_cu);
            if(utilization < 0.6f)
            {
                std::cout << "skip low utilization config: " << utilization << std::endl;
                return false;
            }
        }

        return true;
    }

    CK_TILE_HOST static bool IsSupportedArgument(const HostArgs& hargs, const KernelArgs& kargs)
    {
        // limitation: only support 1x1 conv
        if constexpr(ConvSpec != ConvFwdSpecEnum::F1x1_S1_D1_P0 &&
                     ConvSpec != ConvFwdSpecEnum::F1x1_S2_D1_P0)
        {
            return false;
        }

        if(!IsApplicableConvProblem<ConvSpec>(hargs))
        {
            return false;
        }

        if(GetLdsByteSize() > get_hcu_lds_capacity())
        {
            return false;
        }

        if(!IsEfficientConfig(hargs, kargs))
        {
            return false;
        }

        // TODO: add group support
        if(kargs.num_group != 1)
        {
            return false;
        }

        // limitation: pad mnk is not supported in this version
        const index_t NPQ =
            hargs.output.lengths[1] * hargs.output.lengths[3] * hargs.output.lengths[4];
        const index_t K = hargs.weight.lengths[1];
        const index_t C = hargs.weight.lengths[2];
        if(NPQ != kargs.out_desc.get_length(number<0>{}) ||
           K != kargs.out_desc.get_length(number<1>{}) ||
           C != kargs.wei_desc.get_length(number<1>{}))
        {
            return false;
        }

        // device check
        const auto target_enum = get_hcu_target_enum();

        if(target_enum < hcu_target_enum::gfx936)
        {
            return false;
        }

        // cache swizzle only support 64 * (2^n) as const_stride
        if(!(ck_tile::ispow2(kargs.in_const_stride) && ck_tile::ispow2(kargs.wei_const_stride)))
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

        if(!GemmPipeline::IsSupported(GetNumLoop(kargs)))
        {
            return false;
        }

        return true;
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetLdsByteSize()
    {
        return max(GemmPipeline::GetLdsByteSize(), EpiloguePipeline::GetLdsByteSize());
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetMaxOccupancy()
    {
        return min(3, get_hcu_lds_capacity() / GetLdsByteSize());
    }

    template <bool has_hot_loop>
    CK_TILE_DEVICE void operator()(KernelArgs kargs, bool_constant<has_hot_loop>) const
    {
        auto in_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.in_ptr, kargs.in_desc, kargs.in_const_stride);
        auto wei_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.wei_ptr, kargs.wei_desc, kargs.wei_const_stride);
        auto out_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.out_ptr, kargs.out_desc);
        auto bias_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.bias_ptr, kargs.bias_desc);
        auto res_tensor_view =
            make_tensor_view<address_space_enum::global>(kargs.res_ptr, kargs.out_desc);

        // LDS allocation
        __shared__ char p_smem[GetLdsByteSize() > CK_TILE_BLOCK_MAX_LDS_SIZE
                                   ? CK_TILE_BLOCK_MAX_LDS_SIZE
                                   : GetLdsByteSize()];

        const auto num_tiles = kargs.tile_partitioner.GetNumTiles();

        const index_t num_loop = GetNumLoop(kargs);

        // A matrix in LDS
        constexpr auto in_wg_lds_desc   = Policy::template MakeInLdsWGDesc<Problem>();
        constexpr auto in_lds_elem_size = Policy::template GetInLdsElemSize<Problem>();

        // B matrix in LDS
        constexpr auto wei_wg_lds_desc   = Policy::template MakeWeiLdsWGDesc<Problem>();
        constexpr auto wei_lds_elem_size = Policy::template GetWeiLdsElemSize<Problem>();

        // for epilogue
        constexpr auto out_tile_lens = EpiloguePipeline::GetTileLengths();

        // run with specific warp group organization
        if constexpr(GemmPipeline::is_input_shared)
        {
            // lds windows for warp groups
            constexpr auto in_lds_elem_offset        = 0;
            constexpr auto wei_lds_elem_offset_major = Problem::NumLdsStages * in_lds_elem_size;
            constexpr auto wei_lds_elem_offset_minor =
                wei_lds_elem_offset_major + Problem::NumLdsStages * wei_lds_elem_size;

            // in lds windows: shared
            auto in_wg_lds_windows =
                lds_utils::AllocateLdsWindows<InDataType, Problem::NumLdsStages>(
                    p_smem,
                    in_lds_elem_size,
                    in_lds_elem_offset,
                    KPerBlock,
                    make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    in_wg_lds_desc);

            // wei lds windows: private
            auto wei_wg_lds_windows_major =
                lds_utils::AllocateLdsWindows<WeiDataType, Problem::NumLdsStages>(
                    p_smem,
                    wei_lds_elem_size,
                    wei_lds_elem_offset_major,
                    KPerBlock,
                    make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    wei_wg_lds_desc);

            auto wei_wg_lds_windows_minor =
                lds_utils::AllocateLdsWindows<WeiDataType, Problem::NumLdsStages>(
                    p_smem,
                    wei_lds_elem_size,
                    wei_lds_elem_offset_minor,
                    KPerBlock,
                    make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    wei_wg_lds_desc);

            // launch wasp pipelines
            if(GemmPipeline::IsProducerWG())
            {
                // in dram window: shared
                auto in_wg_dram_window = make_tile_window_conv_fwd_activation_async_v2<
                    lds_layout_traits<KPerBlock>::value>(
                    in_tensor_view,
                    sequence<number<MPerWG>{}, number<KPerBlock>{}>{},
                    FilterLengths,
                    Policy::template MakeInDramTileDstr<Problem>(),
                    InLayout{});

                // wei dram window: private
                auto wei_wg_dram_window_major =
                    make_tile_window_conv_fwd_filter_async_v2<lds_layout_traits<KPerBlock>::value>(
                        wei_tensor_view,
                        sequence<number<NPerWG>{}, number<KPerBlock>{}>{},
                        FilterLengths,
                        Policy::template MakeWeiDramTileDstr<Problem>(),
                        WeiLayout{});

                auto wei_wg_dram_window_minor =
                    make_tile_window_conv_fwd_filter_async_v2<lds_layout_traits<KPerBlock>::value>(
                        wei_tensor_view,
                        sequence<number<NPerWG>{}, number<KPerBlock>{}>{},
                        FilterLengths,
                        Policy::template MakeWeiDramTileDstr<Problem>(),
                        WeiLayout{});

                for(int tile_idx = get_block_1d_id(); tile_idx < num_tiles; tile_idx += gridDim.x)
                {
                    // TG work idx
                    const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(tile_idx);
                    const index_t block_work_idx_m =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
                    const index_t block_work_idx_n =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);

                    // set window origin explicitly
                    in_wg_dram_window.set_window_origin(make_multi_index(block_work_idx_m, 0));
                    wei_wg_dram_window_major.set_window_origin(
                        make_multi_index(block_work_idx_n, 0));
                    wei_wg_dram_window_minor.set_window_origin(
                        make_multi_index(block_work_idx_n + NPerWG, 0));

                    __builtin_amdgcn_sched_barrier(0);
                    wg_sync(bool_constant<true>{});
                    __builtin_amdgcn_sched_barrier(0);

                    GemmPipeline{}(in_wg_dram_window,
                                   wei_wg_dram_window_major,
                                   wei_wg_dram_window_minor,
                                   in_wg_lds_windows,
                                   wei_wg_lds_windows_major,
                                   wei_wg_lds_windows_minor,
                                   num_loop,
                                   bool_constant<has_hot_loop>{});

                    EpiloguePipeline{}();
                }
            }
            else if(GemmPipeline::IsMajorComputeWG())
            {
                const auto block_gemm = BlockGemm{};

                const auto in_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetAWarpWindows(in_wg_lds_windows(i)); },
                    number<Problem::NumLdsStages>{});

                const auto wei_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetBWarpWindows(wei_wg_lds_windows_major(i)); },
                    number<Problem::NumLdsStages>{});

                for(int tile_idx = get_block_1d_id(); tile_idx < num_tiles; tile_idx += gridDim.x)
                {
                    // TG work idx
                    const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(tile_idx);
                    const index_t block_work_idx_m =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
                    const index_t block_work_idx_n =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);
                    // for epilogue
                    const auto out_block_work_idx =
                        make_multi_index(block_work_idx_m, block_work_idx_n);

                    __builtin_amdgcn_sched_barrier(0);
                    wg_sync(bool_constant<true>{});
                    __builtin_amdgcn_sched_barrier(0);

                    const auto acc_block_tensor = GemmPipeline{}(in_warp_windows,
                                                                 wei_warp_windows,
                                                                 block_gemm,
                                                                 num_loop,
                                                                 bool_constant<has_hot_loop>{},
                                                                 number<0>{});

                    // epilogue
                    auto out_dram_window =
                        make_tile_window(out_tensor_view, out_tile_lens, out_block_work_idx);

                    auto bias_dram_window =
                        make_tile_window(bias_tensor_view, out_tile_lens, out_block_work_idx);

                    auto res_dram_window =
                        make_tile_window(res_tensor_view, out_tile_lens, out_block_work_idx);

                    EpiloguePipeline{}(p_smem,
                                       acc_block_tensor,
                                       out_dram_window,
                                       bias_dram_window,
                                       res_dram_window,
                                       number<0>{});
                }
            }
            else if(GemmPipeline::IsMinorComputeWG())
            {
                const auto block_gemm = BlockGemm{};

                const auto in_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetAWarpWindows(in_wg_lds_windows(i)); },
                    number<Problem::NumLdsStages>{});

                const auto wei_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetBWarpWindows(wei_wg_lds_windows_minor(i)); },
                    number<Problem::NumLdsStages>{});

                for(int tile_idx = get_block_1d_id(); tile_idx < num_tiles; tile_idx += gridDim.x)
                {
                    // TG work idx
                    const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(tile_idx);
                    const index_t block_work_idx_m =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
                    const index_t block_work_idx_n =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);
                    // for epilogue
                    const auto out_block_work_idx =
                        make_multi_index(block_work_idx_m, block_work_idx_n);

                    __builtin_amdgcn_sched_barrier(0);
                    wg_sync(bool_constant<true>{});
                    __builtin_amdgcn_sched_barrier(0);

                    const auto acc_block_tensor = GemmPipeline{}(in_warp_windows,
                                                                 wei_warp_windows,
                                                                 block_gemm,
                                                                 num_loop,
                                                                 bool_constant<has_hot_loop>{},
                                                                 number<1>{});

                    // epilogue
                    auto out_dram_window =
                        make_tile_window(out_tensor_view,
                                         out_tile_lens,
                                         out_block_work_idx + make_multi_index(0, NPerWG));

                    auto bias_dram_window =
                        make_tile_window(bias_tensor_view,
                                         out_tile_lens,
                                         out_block_work_idx + make_multi_index(0, NPerWG));

                    auto res_dram_window =
                        make_tile_window(res_tensor_view,
                                         out_tile_lens,
                                         out_block_work_idx + make_multi_index(0, NPerWG));

                    EpiloguePipeline{}(p_smem,
                                       acc_block_tensor,
                                       out_dram_window,
                                       bias_dram_window,
                                       res_dram_window,
                                       number<1>{});
                }
            }
        }
        else
        {
            // lds windows for warp groups
            constexpr auto in_lds_elem_offset_major = 0;
            constexpr auto in_lds_elem_offset_minor = Problem::NumLdsStages * in_lds_elem_size;
            constexpr auto wei_lds_elem_offset =
                in_lds_elem_offset_minor + Problem::NumLdsStages * in_lds_elem_size;

            // in lds windows: private
            auto in_wg_lds_windows_major =
                lds_utils::AllocateLdsWindows<InDataType, Problem::NumLdsStages>(
                    p_smem,
                    in_lds_elem_size,
                    in_lds_elem_offset_major,
                    KPerBlock,
                    make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    in_wg_lds_desc);

            auto in_wg_lds_windows_minor =
                lds_utils::AllocateLdsWindows<InDataType, Problem::NumLdsStages>(
                    p_smem,
                    in_lds_elem_size,
                    in_lds_elem_offset_minor,
                    KPerBlock,
                    make_tuple(number<MPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    in_wg_lds_desc);

            // wei lds windows: shared
            auto wei_wg_lds_windows =
                lds_utils::AllocateLdsWindows<WeiDataType, Problem::NumLdsStages>(
                    p_smem,
                    wei_lds_elem_size,
                    wei_lds_elem_offset,
                    KPerBlock,
                    make_tuple(number<NPerWG>{}, number<KPerBlock>{}),
                    make_multi_index(0, 0),
                    wei_wg_lds_desc);

            // launch wasp pipelines
            if(GemmPipeline::IsProducerWG())
            {
                // in dram window: private
                auto in_wg_dram_window_major = make_tile_window_conv_fwd_activation_async_v2<
                    lds_layout_traits<KPerBlock>::value>(
                    in_tensor_view,
                    sequence<number<MPerWG>{}, number<KPerBlock>{}>{},
                    FilterLengths,
                    Policy::template MakeInDramTileDstr<Problem>(),
                    InLayout{});

                auto in_wg_dram_window_minor = make_tile_window_conv_fwd_activation_async_v2<
                    lds_layout_traits<KPerBlock>::value>(
                    in_tensor_view,
                    sequence<number<MPerWG>{}, number<KPerBlock>{}>{},
                    FilterLengths,
                    Policy::template MakeInDramTileDstr<Problem>(),
                    InLayout{});

                // wei dram window: shared
                auto wei_wg_dram_window =
                    make_tile_window_conv_fwd_filter_async_v2<lds_layout_traits<KPerBlock>::value>(
                        wei_tensor_view,
                        sequence<number<NPerWG>{}, number<KPerBlock>{}>{},
                        FilterLengths,
                        Policy::template MakeWeiDramTileDstr<Problem>(),
                        WeiLayout{});

                for(int tile_idx = get_block_1d_id(); tile_idx < num_tiles; tile_idx += gridDim.x)
                {
                    // TG work idx
                    const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(tile_idx);
                    const index_t block_work_idx_m =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
                    const index_t block_work_idx_n =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);

                    // set window origin explicitly
                    in_wg_dram_window_major.set_window_origin(
                        make_multi_index(block_work_idx_m, 0));
                    in_wg_dram_window_minor.set_window_origin(
                        make_multi_index(block_work_idx_m + MPerWG, 0));
                    wei_wg_dram_window.set_window_origin(make_multi_index(block_work_idx_n, 0));

                    __builtin_amdgcn_sched_barrier(0);
                    wg_sync(bool_constant<true>{});
                    __builtin_amdgcn_sched_barrier(0);

                    GemmPipeline{}(wei_wg_dram_window,
                                   in_wg_dram_window_major,
                                   in_wg_dram_window_minor,
                                   wei_wg_lds_windows,
                                   in_wg_lds_windows_major,
                                   in_wg_lds_windows_minor,
                                   num_loop,
                                   bool_constant<has_hot_loop>{});

                    EpiloguePipeline{}();
                }
            }
            else if(GemmPipeline::IsMajorComputeWG())
            {
                const auto block_gemm = BlockGemm{};

                const auto wei_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetBWarpWindows(wei_wg_lds_windows(i)); },
                    number<Problem::NumLdsStages>{});

                const auto in_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetAWarpWindows(in_wg_lds_windows_major(i)); },
                    number<Problem::NumLdsStages>{});

                for(int tile_idx = get_block_1d_id(); tile_idx < num_tiles; tile_idx += gridDim.x)
                {
                    // TG work idx
                    const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(tile_idx);
                    const index_t block_work_idx_m =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
                    const index_t block_work_idx_n =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);
                    // for epilogue
                    const auto out_block_work_idx =
                        make_multi_index(block_work_idx_m, block_work_idx_n);

                    __builtin_amdgcn_sched_barrier(0);
                    wg_sync(bool_constant<true>{});
                    __builtin_amdgcn_sched_barrier(0);

                    const auto acc_block_tensor = GemmPipeline{}(wei_warp_windows,
                                                                 in_warp_windows,
                                                                 block_gemm,
                                                                 num_loop,
                                                                 bool_constant<has_hot_loop>{},
                                                                 number<0>{});

                    // epilogue
                    auto out_dram_window =
                        make_tile_window(out_tensor_view, out_tile_lens, out_block_work_idx);

                    auto bias_dram_window =
                        make_tile_window(bias_tensor_view, out_tile_lens, out_block_work_idx);

                    auto res_dram_window =
                        make_tile_window(res_tensor_view, out_tile_lens, out_block_work_idx);

                    EpiloguePipeline{}(p_smem,
                                       acc_block_tensor,
                                       out_dram_window,
                                       bias_dram_window,
                                       res_dram_window,
                                       number<0>{});
                }
            }
            else if(GemmPipeline::IsMinorComputeWG())
            {
                const auto block_gemm = BlockGemm{};

                const auto wei_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetBWarpWindows(wei_wg_lds_windows(i)); },
                    number<Problem::NumLdsStages>{});

                const auto in_warp_windows = generate_tuple(
                    [&](auto i) { return block_gemm.GetAWarpWindows(in_wg_lds_windows_minor(i)); },
                    number<Problem::NumLdsStages>{});

                for(int tile_idx = get_block_1d_id(); tile_idx < num_tiles; tile_idx += gridDim.x)
                {
                    // TG work idx
                    const auto block_work_idx = kargs.tile_partitioner.GetOutputTileIndex(tile_idx);
                    const index_t block_work_idx_m =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<1>{}] * MPerBlock);
                    const index_t block_work_idx_n =
                        __builtin_amdgcn_readfirstlane(block_work_idx[number<2>{}] * NPerBlock);

                    // for epilogue
                    const auto out_block_work_idx =
                        make_multi_index(block_work_idx_m, block_work_idx_n);

                    __builtin_amdgcn_sched_barrier(0);
                    wg_sync(bool_constant<true>{});
                    __builtin_amdgcn_sched_barrier(0);

                    const auto acc_block_tensor = GemmPipeline{}(wei_warp_windows,
                                                                 in_warp_windows,
                                                                 block_gemm,
                                                                 num_loop,
                                                                 bool_constant<has_hot_loop>{},
                                                                 number<1>{});

                    // epilogue
                    auto out_dram_window =
                        make_tile_window(out_tensor_view,
                                         out_tile_lens,
                                         out_block_work_idx + make_multi_index(MPerWG, 0));

                    auto bias_dram_window =
                        make_tile_window(bias_tensor_view,
                                         out_tile_lens,
                                         out_block_work_idx + make_multi_index(MPerWG, 0));

                    auto res_dram_window =
                        make_tile_window(res_tensor_view,
                                         out_tile_lens,
                                         out_block_work_idx + make_multi_index(MPerWG, 0));

                    EpiloguePipeline{}(p_smem,
                                       acc_block_tensor,
                                       out_dram_window,
                                       bias_dram_window,
                                       res_dram_window,
                                       number<1>{});
                }
            }
        }
    }
};

} // namespace ck_tile
