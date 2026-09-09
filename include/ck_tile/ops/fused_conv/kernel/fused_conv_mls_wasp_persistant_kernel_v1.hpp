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
#include "ck_tile/ops/fused_conv/utility/grouped_fused_conv_ptr_offset.hpp"

namespace ck_tile {

template <hcu_target_enum HcuArch_,
          typename TilePartitioner_,
          typename GemmPipeline_,
          typename EpiloguePipeline_>
struct FusedConvMlsWaspPersistantKernelV1
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

    static constexpr auto HcuArch = HcuArch_;

    static_assert(HcuArch == hcu_target_enum::gfx938 || HcuArch == hcu_target_enum::gfx946,
                  "FusedConvMlsWaspKernelV1 only support gfx938/gfx946");

    using BlockGemm = decltype(Policy::template GetBlockwiseGemm<HcuArch, Problem>());

    static constexpr index_t NDimSpatial = Problem::NDimSpatial;

    using HostArgs = FusedConvHostArgs<NDimSpatial>;

    static constexpr index_t NDim = HostArgs::NDim;

    static constexpr auto ConvSpec = Problem::ConvSpec;

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

    static constexpr auto WaspHelper = wasp_helper<Problem::SubWGSize, Problem::BlockSize, true>{};

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

        index_t mls_stride_a;
        index_t mls_stride_b;

        index_t mls_pad_m;
        index_t mls_pad_n;

        InDesc in_desc;
        WeiDesc wei_desc;
        OutDesc out_desc;
        BiasDesc bias_desc;
        OutDesc res_desc;

        InElementwiseOp in_element_op;
        WeiElementwiseOp wei_element_op;
        OutElementwiseOp out_element_op;

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

        const index_t mls_a_stride = hargs.input.strides[4];
        const index_t mls_b_stride = hargs.weight.strides[4];

        const index_t NPQ =
            hargs.output.lengths[1] * hargs.output.lengths[3] * hargs.output.lengths[4];
        const index_t K = hargs.weight.lengths[1];

        const index_t mls_pad_m = out_desc_m_n.get_length(number<0>{}) - NPQ;
        const index_t mls_pad_n = out_desc_m_n.get_length(number<1>{}) - K;

#if 0
        std::cout << "mls_pad_m: " << mls_pad_m << std::endl;
        std::cout << "mls_pad_n: " << mls_pad_n << std::endl;

        std::cout << "mls_a_stride: " << mls_a_stride << std::endl;
        std::cout << "mls_b_stride: " << mls_b_stride << std::endl;
#endif

        return KernelArgs{
            static_cast<const InDataType*>(hargs.in_ptr),
            static_cast<const WeiDataType*>(hargs.wei_ptr),
            static_cast<OutDataType*>(hargs.out_ptr),
            static_cast<const BiasDataType*>(hargs.bias_ptr),
            static_cast<const OutDataType*>(hargs.res_ptr),
            num_group,
            mls_a_stride,
            mls_b_stride,
            mls_pad_m,
            mls_pad_n,
            in_desc_b_m_k,
            wei_desc_b_n_k,
            out_desc_m_n,
            bias_desc_m_n,
            res_desc_m_n,
            InElementwiseOp{},
            WeiElementwiseOp{},
            OutElementwiseOp{},
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

        // limitation: mls_pad_k is not supported in this version
        const index_t C = hargs.weight.lengths[2];
        if(C != kargs.wei_desc.get_length(number<1>{}))
        {
            return false;
        }

        // device check
        const auto target_enum = get_hcu_target_enum();

        // gfx938 specified
        if(target_enum != HcuArch)
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
        constexpr auto mls_alt_a = Problem::MmmacInterleave;
        constexpr auto mls_alt_b = Problem::NmmacInterleave;

        // compute grouped conv ptr offset
        const index_t num_blocks_per_group =
            __builtin_amdgcn_readfirstlane(get_grid_size() / kargs.num_group);
        const index_t g_idx =
            __builtin_amdgcn_readfirstlane(get_block_1d_id() / num_blocks_per_group);
        const index_t local_block_id = __builtin_amdgcn_readfirstlane(
            get_block_1d_id() - g_idx * num_blocks_per_group);

        const long_index_t in_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetAPtrOffset(g_idx)));
        const long_index_t wei_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetBPtrOffset(g_idx)));
        const long_index_t out_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetCPtrOffset(g_idx)));
        const long_index_t bias_g_offset = __builtin_amdgcn_readfirstlane(
            static_cast<long_index_t>(kargs.grouped_conv_ptr_offset.GetDPtrOffset(g_idx)));

        auto in_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.in_ptr + in_g_offset, kargs.in_desc);
        auto wei_tensor_view = make_hcu_tensor_view<address_space_enum::global>(
            kargs.wei_ptr + wei_g_offset, kargs.wei_desc);
        auto out_tensor_view = make_tensor_view<address_space_enum::global>(
            kargs.out_ptr + out_g_offset, kargs.out_desc);
        auto bias_tensor_view = make_tensor_view<address_space_enum::global>(
            kargs.bias_ptr + bias_g_offset, kargs.bias_desc);
        auto res_tensor_view = make_tensor_view<address_space_enum::global>(
            kargs.res_ptr + out_g_offset, kargs.out_desc);

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
                auto in_wg_dram_window =
                    make_tile_window_mls_conv2d_fwd_activation_f1x1s1p0<HcuArch>(
                        in_tensor_view,
                        sequence<number<MPerWG>{}, number<KPerBlock>{}>{},
                        InLayout{},
                        WaspHelper,
                        number<mls_alt_a>{},
                        kargs.mls_stride_a,
                        kargs.mls_pad_m,
                        0);

                // wei dram window: private
                auto wei_wg_dram_window_major = make_tile_window_mls_conv2d_fwd_filter<HcuArch>(
                    wei_tensor_view,
                    sequence<number<NPerWG>{}, number<KPerBlock>{}>{},
                    sequence<1, 1>{},
                    WeiLayout{},
                    WaspHelper,
                    number<mls_alt_b>{},
                    kargs.mls_stride_b,
                    kargs.mls_pad_n,
                    0);

                auto wei_wg_dram_window_minor = make_tile_window_mls_conv2d_fwd_filter<HcuArch>(
                    wei_tensor_view,
                    sequence<number<NPerWG>{}, number<KPerBlock>{}>{},
                    sequence<1, 1>{},
                    WeiLayout{},
                    WaspHelper,
                    number<mls_alt_b>{},
                    kargs.mls_stride_b,
                    kargs.mls_pad_n,
                    0);

                for(int tile_idx = local_block_id; tile_idx < num_tiles;
                    tile_idx += num_blocks_per_group)
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

                for(int tile_idx = local_block_id; tile_idx < num_tiles;
                    tile_idx += num_blocks_per_group)
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

                    const auto acc_block_tensor = GemmPipeline{}(in_wg_lds_windows,
                                                                 wei_wg_lds_windows_major,
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

                for(int tile_idx = local_block_id; tile_idx < num_tiles;
                    tile_idx += num_blocks_per_group)
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

                    const auto acc_block_tensor = GemmPipeline{}(in_wg_lds_windows,
                                                                 wei_wg_lds_windows_minor,
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
                auto in_wg_dram_window_major =
                    make_tile_window_mls_conv2d_fwd_activation_f1x1s1p0<HcuArch>(
                        in_tensor_view,
                        sequence<number<MPerWG>{}, number<KPerBlock>{}>{},
                        InLayout{},
                        WaspHelper,
                        number<mls_alt_a>{},
                        kargs.mls_stride_a,
                        kargs.mls_pad_m,
                        0);

                auto in_wg_dram_window_minor =
                    make_tile_window_mls_conv2d_fwd_activation_f1x1s1p0<HcuArch>(
                        in_tensor_view,
                        sequence<number<MPerWG>{}, number<KPerBlock>{}>{},
                        InLayout{},
                        WaspHelper,
                        number<mls_alt_a>{},
                        kargs.mls_stride_a,
                        kargs.mls_pad_m,
                        0);

                // wei dram window: shared
                auto wei_wg_dram_window = make_tile_window_mls_conv2d_fwd_filter<HcuArch>(
                    wei_tensor_view,
                    sequence<number<NPerWG>{}, number<KPerBlock>{}>{},
                    sequence<1, 1>{},
                    WeiLayout{},
                    WaspHelper,
                    number<mls_alt_b>{},
                    kargs.mls_stride_b,
                    kargs.mls_pad_n,
                    0);

                for(int tile_idx = local_block_id; tile_idx < num_tiles;
                    tile_idx += num_blocks_per_group)
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

                for(int tile_idx = local_block_id; tile_idx < num_tiles;
                    tile_idx += num_blocks_per_group)
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

                    const auto acc_block_tensor = GemmPipeline{}(wei_wg_lds_windows,
                                                                 in_wg_lds_windows_major,
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

                for(int tile_idx = local_block_id; tile_idx < num_tiles;
                    tile_idx += num_blocks_per_group)
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

                    const auto acc_block_tensor = GemmPipeline{}(wei_wg_lds_windows,
                                                                 in_wg_lds_windows_minor,
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
