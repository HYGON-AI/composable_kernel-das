// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2023, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck/utility/amd_lds.hpp"
#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/multi_index_transform_helper.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/grid/block_to_ctile_map.hpp"
#include "ck/tensor_operation/gpu/grid/multistage_gemm_pipeline_convRxS_v2r1.hpp"
#include "ck/tensor_operation/gpu/block/blockwise_gemm_mmac_tn_v2.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
#include "ck/tensor_operation/gpu/block/thread_group_tensor_slice_transfer_lds_swizzle_conv_fwd_activation.hpp"
#include "ck/tensor_operation/gpu/block/thread_group_tensor_slice_transfer_lds_swizzle_conv_fwd_filter.hpp"
#include "ck/tensor_operation/gpu/block/thread_group_tensor_slice_transfer_v6r3.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"

namespace ck {

template <typename GridwiseGemm,
          typename ADataType,
          typename BDataType,
          typename CDataType,
          typename C0DataType,
          typename C1DataType,
          typename AGridDesc_B_M_K,
          typename BGridDesc_B_N_K,
          typename CShuffleGridDesc_M0_M1_M2_N0_N1_N2,
          typename C0ShuffleGridDesc_M0_M1_M2_N0_N1_N2,
          typename C1ShuffleGridDesc_M0_M1_M2_N0_N1_N2,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename Block2CTileMap,
          bool HasMainKBlockLoop,
          index_t MaxThreadPerBlock = CK_MAX_THREAD_PER_BLOCK,
          index_t MinBlockPerCU     = CK_MIN_BLOCK_PER_CU>
__global__ void
#if CK_USE_LAUNCH_BOUNDS
__launch_bounds__(MaxThreadPerBlock, MinBlockPerCU)
#endif
    kernel_gemm_mmac(
        const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const C0DataType* __restrict__ p_c0_grid,
        const C1DataType* __restrict__ p_c1_grid,
        const AGridDesc_B_M_K a_grid_desc_b_m_k,
        const BGridDesc_B_N_K b_grid_desc_b_n_k,
        const CShuffleGridDesc_M0_M1_M2_N0_N1_N2 cshuffle_grid_desc_m0_m1_m2_n0_n1_n2,
        const C0ShuffleGridDesc_M0_M1_M2_N0_N1_N2 c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
        const C1ShuffleGridDesc_M0_M1_M2_N0_N1_N2 c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
        const AElementwiseOperation a_element_op,
        const BElementwiseOperation b_element_op,
        const CElementwiseOperation c_element_op,
        const Block2CTileMap block_2_ctile_map)
{
#if (!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
     defined(__gfx936__) || defined(__gfx938__))
    __shared__ char p_shared[GridwiseGemm::GetSharedMemoryNumberOfByte()];

    GridwiseGemm::template Run<HasMainKBlockLoop>(p_a_grid,
                                                  p_b_grid,
                                                  p_c_grid,
                                                  p_c0_grid,
                                                  p_c1_grid,
                                                  p_shared,
                                                  a_grid_desc_b_m_k,
                                                  b_grid_desc_b_n_k,
                                                  cshuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                                                  c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                                                  c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                                                  a_element_op,
                                                  b_element_op,
                                                  c_element_op,
                                                  block_2_ctile_map);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = p_c0_grid;
    ignore = p_c1_grid;
    ignore = a_grid_desc_b_m_k;
    ignore = b_grid_desc_b_n_k;
    ignore = cshuffle_grid_desc_m0_m1_m2_n0_n1_n2;
    ignore = c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2;
    ignore = c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2;
    ignore = a_element_op;
    ignore = b_element_op;
    ignore = c_element_op;
    ignore = block_2_ctile_map;
#endif // end of if (defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || defined(__gfx936__) ||
       // defined(__gfx938__))
}

template <index_t BlockSize,
          typename ADataType,
          typename BDataType,
          typename AccDataType,
          typename CDataType,
          typename C0DataType,
          typename C1DataType,
          InMemoryDataOperationEnum CGlobalMemoryDataOperation,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename AGridDesc_B_M_K,
          typename BGridDesc_B_N_K,
          typename CGridDesc_M_N,
          typename C0GridDesc_M_N,
          typename C1GridDesc_M_N,
          index_t MPerBlock,
          index_t NPerBlock,
          index_t KPerBlock,
          index_t KPack,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MwaveRepeat,
          index_t NwaveRepeat,
          index_t MmmacRepeat,
          index_t NmmacRepeat,
          index_t MmmacInterleave,
          index_t NmmacInterleave,
          typename ABlockTransferThreadClusterLengths_B_M_K,
          index_t ABlockTransferSrcVectorDim,
          index_t ABlockTransferSrcScalarPerVector,
          typename BBlockTransferThreadClusterLengths_B_N_K,
          index_t BBlockTransferSrcVectorDim,
          index_t BBlockTransferSrcScalarPerVector,
          index_t CShuffleMwaveRepeatPerShuffle,
          index_t CShuffleNwaveRepeatPerShuffle,
          typename CShuffleBlockTransferClusterLengths_M0_M1_M2_N0_N1_N2,
          index_t CShuffleBlockTransferDstScalarPerVector,
          index_t NumGemmKPrefetchStage,
          index_t ConvFilterR,
          index_t ConvFilterS,
          bool a_oob_check,
          bool b_oob_check,
          bool a_cache_swizzle,
          bool b_cache_swizzle,
          index_t occupancy>
struct GridwiseGemm_mmac_tn_mk_nk_mn_v2r1_cdeop_cshuffle
{
    // A/B elementwise operation not supported
    static_assert(
        is_same_v<AElementwiseOperation, ck::tensor_operation::element_wise::PassThrough>);
    static_assert(
        is_same_v<BElementwiseOperation, ck::tensor_operation::element_wise::PassThrough>);

    // FIXME: get incorrect results with mmac repeat/interleave
    static_assert(MmmacRepeat == 1 && MmmacInterleave == 1 && NmmacRepeat == 1 &&
                  NmmacInterleave == 1);

    static constexpr auto I0  = Number<0>{};
    static constexpr auto I1  = Number<1>{};
    static constexpr auto I2  = Number<2>{};
    static constexpr auto I3  = Number<3>{};
    static constexpr auto I4  = Number<4>{};
    static constexpr auto I5  = Number<5>{};
    static constexpr auto I6  = Number<6>{};
    static constexpr auto I7  = Number<7>{};
    static constexpr auto I8  = Number<8>{};
    static constexpr auto I9  = Number<9>{};
    static constexpr auto I10 = Number<10>{};
    static constexpr auto I11 = Number<11>{};

    static constexpr index_t Mwaves =
        MPerBlock / (MwaveRepeat * MmmacRepeat * MPerMmac * MmmacInterleave);
    static constexpr index_t Nwaves =
        NPerBlock / (NwaveRepeat * NmmacRepeat * NPerMmac * NmmacInterleave);

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    static constexpr bool ALdsDirectLoad = false;
    static constexpr bool BLdsDirectLoad = false;

    using MultiStageGemmPipeline =
        remove_cvref_t<decltype(MultiStageGemmPipeline_ConvRxS_v2r1<NumGemmKPrefetchStage,
                                                                    ConvFilterR,
                                                                    ConvFilterS,
                                                                    ALdsDirectLoad,
                                                                    BLdsDirectLoad>())>;

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    __host__ __device__ static constexpr auto GetABlockDescriptor_MPerBlock_KPerBlock()
    {

        return make_naive_tensor_descriptor_packed(
            make_tuple(Number<MPerBlock>{}, Number<KPerBlock>{}));
    }

    __host__ __device__ static constexpr auto GetBBlockDescriptor_NPerBlock_KPerBlock()
    {

        return make_naive_tensor_descriptor_packed(
            make_tuple(Number<NPerBlock>{}, Number<KPerBlock>{}));
    }

    __host__ __device__ static constexpr auto GetABlockDescriptor_B_MPerBlock_KPerBlock()
    {

        return make_naive_tensor_descriptor_packed(
            make_tuple(I1, Number<MPerBlock>{}, Number<KPerBlock>{}));
    }

    __host__ __device__ static constexpr auto GetBBlockDescriptor_B_NPerBlock_KPerBlock()
    {

        return make_naive_tensor_descriptor_packed(
            make_tuple(I1, Number<NPerBlock>{}, Number<KPerBlock>{}));
    }

    __host__ __device__ static constexpr auto GetCShuffleBlockDescriptor_M0_M1_M2_N0_N1_N2()
    {
        constexpr auto cshuffle_block_desc_m0_m1_m2_n0_n1_n2 = make_naive_tensor_descriptor_packed(
            make_tuple(I1,
                       Number<CShuffleMwaveRepeatPerShuffle>{},
                       Number<Mwaves * MmmacRepeat * MPerMmac * MmmacInterleave>{},
                       I1,
                       Number<CShuffleNwaveRepeatPerShuffle>{},
                       Number<Nwaves * NmmacRepeat * NPerMmac * NmmacInterleave>{}));

        return cshuffle_block_desc_m0_m1_m2_n0_n1_n2;
    }

    __host__ __device__ static constexpr index_t GetSharedMemoryNumberOfByte()
    {
        // LDS allocation for A and B: be careful of alignment
        constexpr auto a_block_desc = GetABlockDescriptor_MPerBlock_KPerBlock();

        constexpr auto b_block_desc = GetBBlockDescriptor_NPerBlock_KPerBlock();

        constexpr auto a_block_space_size_aligned =
            math::integer_least_multiple(a_block_desc.GetElementSpaceSize(), Number<KPerBlock>{});

        constexpr auto b_block_space_size_aligned =
            math::integer_least_multiple(b_block_desc.GetElementSpaceSize(), Number<KPerBlock>{});

        // LDS allocation for CShuffle in LDS
        constexpr auto cshuffle_block_desc_m0_m1_m2_n0_n1_n2 =
            GetCShuffleBlockDescriptor_M0_M1_M2_N0_N1_N2();

        constexpr auto cshuffle_block_space_size =
            cshuffle_block_desc_m0_m1_m2_n0_n1_n2.GetElementSpaceSize();

        if constexpr(occupancy >= 1 && occupancy <= 4)
        {
            return math::max((a_block_space_size_aligned * sizeof(AStorageType) +
                              b_block_space_size_aligned * sizeof(BStorageType)),
                             cshuffle_block_space_size * sizeof(CDataType),
                             size_t(60000 / occupancy));
        }
        else
        {
            return math::max((a_block_space_size_aligned * sizeof(AStorageType) +
                              b_block_space_size_aligned * sizeof(BStorageType)),
                             cshuffle_block_space_size * sizeof(CDataType));
        }
    }

    // block_id to matrix tile idx (m0, n0) mapping are controlled by {M01, N01}
    template <typename Block2CTileMap>
    __host__ __device__ static constexpr bool
    CheckValidity(const AGridDesc_B_M_K& a_grid_desc_b_m_k,
                  const BGridDesc_B_N_K& b_grid_desc_b_n_k,
                  const CGridDesc_M_N& c_grid_desc_m_n,
                  const C0GridDesc_M_N& c0_grid_desc_m_n,
                  const C1GridDesc_M_N& c1_grid_desc_m_n,
                  const Block2CTileMap& block_2_ctile_map)
    {
        static_assert((MPerBlock % (MwaveRepeat * MmmacRepeat * MPerMmac * MmmacInterleave) == 0) &&
                          (NPerBlock % (NwaveRepeat * NmmacRepeat * NPerMmac * NmmacInterleave)) ==
                              0,
                      "Invalid tuning param!");

        const auto M = a_grid_desc_b_m_k.GetLength(I1);
        const auto N = b_grid_desc_b_n_k.GetLength(I1);
        const auto K = b_grid_desc_b_n_k.GetLength(I2);

        if(!(M % MPerBlock == 0 && N % NPerBlock == 0 && K % KPerBlock == 0))
            return false;

        // check gridwise gemm pipeline
        const auto num_k_loop = K / KPerBlock;

        if(!MultiStageGemmPipeline::IsSupported(num_k_loop))
        {
            return false;
        }

        if(!block_2_ctile_map.CheckValidity(c_grid_desc_m_n))
        {
            return false;
        }

        if(c_grid_desc_m_n.GetLength(I0) != c0_grid_desc_m_n.GetLength(I0))
        {
            return false;
        }

        if(c_grid_desc_m_n.GetLength(I1) != c0_grid_desc_m_n.GetLength(I1))
        {
            return false;
        }

        if(c_grid_desc_m_n.GetLength(I0) != c1_grid_desc_m_n.GetLength(I0))
        {
            return false;
        }

        if(c_grid_desc_m_n.GetLength(I1) != c1_grid_desc_m_n.GetLength(I1))
        {
            return false;
        }

        // TODO: also check validity of all components (blockwise-copy, threadwise-copy, etc)
        return true;
    }

    __host__ __device__ static constexpr bool CalculateHasMainKBlockLoop(index_t K)
    {
        const index_t num_loop = K / KPerBlock;

        return MultiStageGemmPipeline::CalculateHasMainLoop(num_loop);
    }

    template <typename CGridDesc_M_N_>
    __host__ __device__ static constexpr auto
    MakeCShuffleGridDescriptor_M0_M1_M2_N0_N1_N2(const CGridDesc_M_N_& c_grid_desc_m_n)
    {
        const auto M = c_grid_desc_m_n.GetLength(I0);
        const auto N = c_grid_desc_m_n.GetLength(I1);

        const auto Mblocks = M / MPerBlock;
        const auto Nblocks = N / NPerBlock;

        const auto cshuffle_grid_desc_m0_m1_m2_n0_n1_n2 = transform_tensor_descriptor(
            c_grid_desc_m_n,
            make_tuple(
                make_unmerge_transform(make_tuple(
                    Mblocks, MwaveRepeat, Mwaves * MmmacRepeat * MPerMmac * MmmacInterleave)),
                make_unmerge_transform(make_tuple(
                    Nblocks, NwaveRepeat, Nwaves * NmmacRepeat * NPerMmac * NmmacInterleave))),
            make_tuple(Sequence<0>{}, Sequence<1>{}),
            make_tuple(Sequence<0, 1, 2>{}, Sequence<3, 4, 5>{}));

        return cshuffle_grid_desc_m0_m1_m2_n0_n1_n2;
    }

    // return block_id to C matrix tile idx (m0, n0) mapping
    __host__ __device__ static constexpr auto MakeDefaultBlock2CTileMap(
        const CGridDesc_M_N& c_grid_desc_m_n, index_t M01, index_t N01, index_t KBatch)
    {
        return BlockToCTileMap_KSplit_M00_N00_M01_N01<MPerBlock, NPerBlock, CGridDesc_M_N>(
            c_grid_desc_m_n, M01, N01, KBatch);
    }

    using CShuffleGridDesc_M0_M1_M2_N0_N1_N2 =
        decltype(MakeCShuffleGridDescriptor_M0_M1_M2_N0_N1_N2(CGridDesc_M_N{}));
    using C0ShuffleGridDesc_M0_M1_M2_N0_N1_N2 =
        decltype(MakeCShuffleGridDescriptor_M0_M1_M2_N0_N1_N2(C0GridDesc_M_N{}));
    using C1ShuffleGridDesc_M0_M1_M2_N0_N1_N2 =
        decltype(MakeCShuffleGridDescriptor_M0_M1_M2_N0_N1_N2(C1GridDesc_M_N{}));
    using DefaultBlock2CTileMap = decltype(MakeDefaultBlock2CTileMap(CGridDesc_M_N{}, 1, 1, 1));

    template <bool HasMainKBlockLoop, typename Block2CTileMap = DefaultBlock2CTileMap>
    __device__ static void
    Run(const ADataType* __restrict__ p_a_grid,
        const BDataType* __restrict__ p_b_grid,
        CDataType* __restrict__ p_c_grid,
        const C0DataType* __restrict__ p_c0_grid,
        const C1DataType* __restrict__ p_c1_grid,
        void* __restrict__ p_shared,
        const AGridDesc_B_M_K& a_grid_desc_b_m_k,
        const BGridDesc_B_N_K& b_grid_desc_b_n_k,
        const CShuffleGridDesc_M0_M1_M2_N0_N1_N2& cshuffle_grid_desc_m0_m1_m2_n0_n1_n2,
        const C0ShuffleGridDesc_M0_M1_M2_N0_N1_N2& c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
        const C1ShuffleGridDesc_M0_M1_M2_N0_N1_N2& c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
        const AElementwiseOperation& /*a_element_op*/,
        const BElementwiseOperation& /*b_element_op*/,
        const CElementwiseOperation& c_element_op,
        const Block2CTileMap& block_2_ctile_map,
        const index_t H,
        const index_t W,
        const index_t delta_h,
        const index_t delta_w,
        const index_t a_offset_delta_c,
        const index_t a_offset_delta_r,
        const index_t a_offset_delta_s,
        const index_t b_offset_delta_c,
        const index_t b_offset_delta_r,
        const index_t b_offset_delta_s,
        const index_t a_const_stride = sizeof(ADataType),
        const index_t b_const_stride = sizeof(BDataType))
    {
        const auto a_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            reinterpret_cast<const AStorageType*>(p_a_grid),
            a_grid_desc_b_m_k.GetElementSpaceSize(),
            a_const_stride);
        const auto b_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            reinterpret_cast<const BStorageType*>(p_b_grid),
            b_grid_desc_b_n_k.GetElementSpaceSize(),
            b_const_stride);

        auto c_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_c_grid, cshuffle_grid_desc_m0_m1_m2_n0_n1_n2.GetElementSpaceSize());

        const auto c0_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_c0_grid, c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2.GetElementSpaceSize());

        const auto c1_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_c1_grid, c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2.GetElementSpaceSize());
        // divide block work by [M, N]
        const auto block_work_idx =
            block_2_ctile_map.CalculateBottomIndex(make_multi_index(get_block_1d_id()));

        if(!block_2_ctile_map.ValidCTileIndex(
               block_work_idx,
               make_tuple(cshuffle_grid_desc_m0_m1_m2_n0_n1_n2.GetLength(I0),
                          cshuffle_grid_desc_m0_m1_m2_n0_n1_n2.GetLength(I3))))
        {
            return;
        }

        const index_t k_batch_id = block_work_idx[I0];

        // HACK: this force m/n_block_data_idx_on_grid into SGPR
        const index_t m_block_data_idx_on_grid =
            __builtin_amdgcn_readfirstlane(block_work_idx[I1] * MPerBlock);

        const index_t n_block_data_idx_on_grid =
            __builtin_amdgcn_readfirstlane(block_work_idx[I2] * NPerBlock);

        // A matrix in LDS memory, dst of blockwise copy
        constexpr auto a_block_desc_m_k = GetABlockDescriptor_MPerBlock_KPerBlock();

        constexpr auto a_block_desc_b_m_k = GetABlockDescriptor_B_MPerBlock_KPerBlock();

        // B matrix in LDS memory, dst of blockwise copy
        constexpr auto b_block_desc_n_k = GetBBlockDescriptor_NPerBlock_KPerBlock();

        constexpr auto b_block_desc_b_n_k = GetBBlockDescriptor_B_NPerBlock_KPerBlock();

        // A matrix blockwise copy
        auto a_blockwise_copy = ThreadGroupTensorSliceTransfer_LdsSwizzle_ConvFwdActivation<
            ThisThreadBlock,
            Sequence<1, MPerBlock, KPerBlock>,
            ABlockTransferThreadClusterLengths_B_M_K,
            ADataType,
            ADataType,
            decltype(a_grid_desc_b_m_k),
            decltype(a_block_desc_b_m_k),
            ABlockTransferSrcVectorDim,
            ABlockTransferSrcScalarPerVector,
            KPack,
            ConvFilterR,
            ConvFilterS,
            NumGemmKPrefetchStage,
            a_oob_check,
            false,
            a_cache_swizzle>(a_grid_desc_b_m_k,
                             make_multi_index(k_batch_id, m_block_data_idx_on_grid, 0),
                             a_block_desc_b_m_k,
                             make_multi_index(0, 0, 0),
                             H,
                             W,
                             delta_h,
                             delta_w,
                             a_offset_delta_c,
                             a_offset_delta_r,
                             a_offset_delta_s);

        // B matrix blockwise copy
        auto b_blockwise_copy = ThreadGroupTensorSliceTransfer_LdsSwizzle_ConvFwdFilter<
            ThisThreadBlock,
            Sequence<1, NPerBlock, KPerBlock>,
            BBlockTransferThreadClusterLengths_B_N_K,
            BDataType,
            BDataType,
            decltype(b_grid_desc_b_n_k),
            decltype(b_block_desc_b_n_k),
            BBlockTransferSrcVectorDim,
            BBlockTransferSrcScalarPerVector,
            KPack,
            ConvFilterR,
            ConvFilterS,
            NumGemmKPrefetchStage,
            a_oob_check,
            false,
            b_cache_swizzle>(b_grid_desc_b_n_k,
                             make_multi_index(k_batch_id, n_block_data_idx_on_grid, 0),
                             b_block_desc_b_n_k,
                             make_multi_index(0, 0, 0),
                             b_offset_delta_c,
                             b_offset_delta_r,
                             b_offset_delta_s);

        auto blockwise_gemm = BlockwiseGemmASmemBSmemCReg_mmac_tn_mk_nk_mn_v2<
            BlockSize,
            ADataType,
            BDataType,
            AccDataType,
            decltype(a_block_desc_m_k),
            decltype(b_block_desc_n_k),
            sizeof(ADataType) * ABlockTransferSrcScalarPerVector,
            sizeof(BDataType) * BBlockTransferSrcScalarPerVector,
            MPerMmac,
            NPerMmac,
            KPack,
            MwaveRepeat,
            NwaveRepeat,
            MmmacRepeat,
            NmmacRepeat,
            MmmacInterleave,
            NmmacInterleave,
            NumGemmKPrefetchStage,
            HasMainKBlockLoop>();

        auto c_thread_buf = blockwise_gemm.GetCThreadBuffer();

        // LDS allocation for A and B: be careful of alignment
        constexpr auto a_block_space_size_aligned = math::integer_least_multiple(
            a_block_desc_m_k.GetElementSpaceSize(), Number<KPerBlock>{});

        constexpr auto a_block_bufs_offset = 0;
        auto a_block_bufs =
            ck::lds_utils::AllocateLdsBuffers<ADataType, 1>(p_shared,
                                                            a_block_desc_m_k.GetElementSpaceSize(),
                                                            a_block_bufs_offset,
                                                            Number<KPerBlock>{});

        constexpr auto b_block_bufs_offset = a_block_space_size_aligned * 1;
        auto b_block_bufs =
            ck::lds_utils::AllocateLdsBuffers<BDataType, 1>(p_shared,
                                                            b_block_desc_n_k.GetElementSpaceSize(),
                                                            b_block_bufs_offset,
                                                            Number<KPerBlock>{});

        constexpr auto a_block_slice_copy_step = make_multi_index(0, 0, KPerBlock);
        constexpr auto b_block_slice_copy_step = make_multi_index(0, 0, KPerBlock);

        // gridwise GEMM pipeline
        const auto K                        = a_grid_desc_b_m_k.GetLength(I2);
        const index_t num_k_block_main_loop = __builtin_amdgcn_readfirstlane(K / KPerBlock);

        MultiStageGemmPipeline::template Run<HasMainKBlockLoop>(blockwise_gemm,
                                                                a_grid_desc_b_m_k,
                                                                a_block_desc_b_m_k,
                                                                a_blockwise_copy,
                                                                a_grid_buf,
                                                                a_block_bufs,
                                                                a_block_slice_copy_step,
                                                                b_grid_desc_b_n_k,
                                                                b_block_desc_b_n_k,
                                                                b_blockwise_copy,
                                                                b_grid_buf,
                                                                b_block_bufs,
                                                                b_block_slice_copy_step,
                                                                c_thread_buf,
                                                                num_k_block_main_loop);

        // output: shuffle C and write out
        {
            static_assert(MwaveRepeat % CShuffleMwaveRepeatPerShuffle == 0 &&
                              NwaveRepeat % CShuffleNwaveRepeatPerShuffle == 0,
                          "wrong cshuffle config!");

            // trans raw mmac output layout to interleaved mmac output layout
            constexpr auto c_m_n0_n1_n2_lens =
                blockwise_gemm.mmac_gemm.GetCMN0N1N2ThreadBlkLengths();

            constexpr auto num_groups_per_blk = c_m_n0_n1_n2_lens[I1];
            constexpr auto group_size         = c_m_n0_n1_n2_lens[I3];
            constexpr auto c_thread_desc_raw  = blockwise_gemm.GetCThreadDescriptorRaw12D();
            constexpr auto c_thread_desc_raw_to_interleaved = transform_tensor_descriptor(
                c_thread_desc_raw,
                make_tuple(make_pass_through_transform(Number<MwaveRepeat>{}),
                           make_pass_through_transform(Number<NwaveRepeat>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<MmmacRepeat>{}),
                           make_pass_through_transform(Number<NmmacRepeat>{}),
                           make_pass_through_transform(Number<num_groups_per_blk>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<group_size>{}),
                           make_pass_through_transform(Number<MmmacInterleave>{}),
                           make_pass_through_transform(I1),
                           make_pass_through_transform(Number<NmmacInterleave>{})),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<8>{},
                           Sequence<9>{},
                           Sequence<10>{},
                           Sequence<6>{},
                           Sequence<11>{},
                           Sequence<7>{}),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{},
                           Sequence<6>{},
                           Sequence<7>{},
                           Sequence<8>{},
                           Sequence<9>{},
                           Sequence<10>{},
                           Sequence<11>{}));

            constexpr auto c_block_desc_interleaved =
                blockwise_gemm.GetCBlockDescriptorInterleaved12D();

            // M0: MwaveRepeat
            // M1: Mwaves
            // M2: MmmacRepeat
            // M3: num_groups_per_blk
            // M4: num_input_blks
            // M5: group_size
            // M6: MmmacInterleave
            constexpr auto M0 = c_block_desc_interleaved.GetLength(I0);
            constexpr auto N0 = c_block_desc_interleaved.GetLength(I1);
            constexpr auto M1 = c_block_desc_interleaved.GetLength(I2);
            constexpr auto N1 = c_block_desc_interleaved.GetLength(I3);
            constexpr auto M2 = c_block_desc_interleaved.GetLength(I4);
            constexpr auto N2 = c_block_desc_interleaved.GetLength(I5);
            constexpr auto M3 = c_block_desc_interleaved.GetLength(I6);
            constexpr auto M4 = c_block_desc_interleaved.GetLength(I7);
            constexpr auto M5 = c_block_desc_interleaved.GetLength(I8);
            constexpr auto M6 = c_block_desc_interleaved.GetLength(I9);
            constexpr auto N3 = c_block_desc_interleaved.GetLength(I10);
            constexpr auto N4 = c_block_desc_interleaved.GetLength(I11);

            // M0: Mblocks, M1: MwaveRepeat, M2: Mwaves * MmmacRepeat * MPerMmac * MmmacInterleave
            // N0: Nblocks, N1: NwaveRepeat, N2: Nwaves * NmmacRepeat * NPerMMac * NmmacInterleave
            constexpr auto cshuffle_block_desc_m0_m1_m2_n0_n1_n2 =
                GetCShuffleBlockDescriptor_M0_M1_M2_N0_N1_N2();

            auto cshuffle_block_buf = make_dynamic_buffer<AddressSpaceEnum::Lds>(
                static_cast<CDataType*>(p_shared),
                cshuffle_block_desc_m0_m1_m2_n0_n1_n2.GetElementSpaceSize());

            constexpr auto cshuffle_block_desc_interleaved = transform_tensor_descriptor(
                cshuffle_block_desc_m0_m1_m2_n0_n1_n2,
                make_tuple(make_freeze_transform(I0),
                           make_pass_through_transform(CShuffleMwaveRepeatPerShuffle),
                           make_unmerge_transform(make_tuple(M1, M2, M3, M4, M5, M6)),
                           make_freeze_transform(I0),
                           make_pass_through_transform(CShuffleNwaveRepeatPerShuffle),
                           make_unmerge_transform(make_tuple(N1, N2, N3, N4))),
                make_tuple(Sequence<0>{},
                           Sequence<1>{},
                           Sequence<2>{},
                           Sequence<3>{},
                           Sequence<4>{},
                           Sequence<5>{}),
                make_tuple(Sequence<>{},
                           Sequence<0>{},
                           Sequence<2, 4, 6, 7, 8, 9>{},
                           Sequence<>{},
                           Sequence<1>{},
                           Sequence<3, 5, 10, 11>{}));

            // calculate origin of thread output tensor on global memory
            //     blockwise GEMM c matrix starting index
            const auto c_thread_mtx_on_block =
                blockwise_gemm.CalculateCThreadOriginDataIndex(I0, I0, I0, I0);

            const index_t m_thread_data_on_block = c_thread_mtx_on_block[I0];

            const index_t n_thread_data_on_block = c_thread_mtx_on_block[I1];

            const auto m_thread_data_on_block_to_m0_m1_m2_m3_m4_m5_m6_adaptor =
                make_single_stage_tensor_adaptor(
                    make_tuple(make_merge_transform(make_tuple(M0, M1, M2, M3, M4, M5, M6))),
                    make_tuple(Sequence<0, 1, 2, 3, 4, 5, 6>{}),
                    make_tuple(Sequence<0>{}));

            const auto m_thread_data_on_block_idx =
                m_thread_data_on_block_to_m0_m1_m2_m3_m4_m5_m6_adaptor.CalculateBottomIndex(
                    make_multi_index(m_thread_data_on_block));

            const auto n_thread_data_on_block_to_n0_n1_n2_n3_n4_adaptor =
                make_single_stage_tensor_adaptor(
                    make_tuple(make_merge_transform(make_tuple(N0, N1, N2, N3, N4))),
                    make_tuple(Sequence<0, 1, 2, 3, 4>{}),
                    make_tuple(Sequence<0>{}));

            const auto n_thread_data_on_block_idx =
                n_thread_data_on_block_to_n0_n1_n2_n3_n4_adaptor.CalculateBottomIndex(
                    make_multi_index(n_thread_data_on_block));

            // cshuffle vgpr -> lds
            auto cshuffle_thread_copy_vgpr_to_lds =
                ThreadwiseTensorSliceTransfer_v1r3<AccDataType,
                                                   CDataType,
                                                   decltype(c_thread_desc_raw_to_interleaved),
                                                   decltype(cshuffle_block_desc_interleaved),
                                                   ck::tensor_operation::element_wise::PassThrough,
                                                   Sequence<CShuffleMwaveRepeatPerShuffle,
                                                            CShuffleNwaveRepeatPerShuffle,
                                                            I1,
                                                            I1,
                                                            M2,
                                                            N2,
                                                            M3,
                                                            I1,
                                                            M5,
                                                            M6,
                                                            I1,
                                                            N4>,
                                                   Sequence<0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11>,
                                                   11,
                                                   NmmacInterleave,
                                                   CGlobalMemoryDataOperation,
                                                   1,
                                                   true>{
                    cshuffle_block_desc_interleaved,
                    make_multi_index(I0,
                                     I0,
                                     m_thread_data_on_block_idx[I1],
                                     n_thread_data_on_block_idx[I1],
                                     m_thread_data_on_block_idx[I2],
                                     n_thread_data_on_block_idx[I2],
                                     m_thread_data_on_block_idx[I3],
                                     m_thread_data_on_block_idx[I4],
                                     m_thread_data_on_block_idx[I5],
                                     m_thread_data_on_block_idx[I6],
                                     n_thread_data_on_block_idx[I3],
                                     n_thread_data_on_block_idx[I4]),
                    ck::tensor_operation::element_wise::PassThrough{}};

            // cshuffle lds -> global
            auto cshuffle_block_copy_lds_to_global = ThreadGroupTensorSliceTransfer_v6r3<
                ThisThreadBlock,            // ThreadGroup
                CElementwiseOperation,      // ElementwiseOperation,
                CGlobalMemoryDataOperation, // DstInMemOp,
                Sequence<1,
                         CShuffleMwaveRepeatPerShuffle,
                         Mwaves * MmmacRepeat * MPerMmac * MmmacInterleave,
                         1,
                         CShuffleNwaveRepeatPerShuffle,
                         Nwaves * NmmacRepeat * NPerMmac * NmmacInterleave>, // BlockSliceLengths,
                CShuffleBlockTransferClusterLengths_M0_M1_M2_N0_N1_N2,
                Sequence<0, 1, 2, 3, 4, 5>, // typename ThreadClusterArrangeOrder,
                CDataType,                  // typename Src0Data,
                C0DataType,                 // typename Src1Data,
                C1DataType,                 // typename Src2Data,
                CDataType,                  // typename DstData,
                decltype(cshuffle_block_desc_m0_m1_m2_n0_n1_n2),
                decltype(c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2),
                decltype(c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2),
                decltype(cshuffle_grid_desc_m0_m1_m2_n0_n1_n2),
                Sequence<0, 1, 2, 3, 4, 5>,              // typename DimAccessOrder,
                5,                                       // index_t VectorDim,
                CShuffleBlockTransferDstScalarPerVector, // index_t ScalarPerVector,
                true,  // bool ThreadTransferSrc0ResetCoordinateAfterRun,
                false, // bool ThreadTransferSrc1ResetCoordinateAfterRun,
                false, // bool ThreadTransferSrc2ResetCoordinateAfterRun,
                false> // bool ThreadTransferDstResetCoordinateAfterRun>
                {cshuffle_block_desc_m0_m1_m2_n0_n1_n2,
                 make_multi_index(0, 0, 0, 0, 0, 0),
                 c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                 make_multi_index(block_work_idx[I1], 0, 0, block_work_idx[I2], 0, 0),
                 c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                 make_multi_index(block_work_idx[I1], 0, 0, block_work_idx[I2], 0, 0),
                 cshuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                 make_multi_index(block_work_idx[I1], 0, 0, block_work_idx[I2], 0, 0),
                 c_element_op};

            constexpr auto m_wave_repeat_forward_step =
                make_multi_index(0, CShuffleMwaveRepeatPerShuffle, 0, 0, 0, 0);
            constexpr auto n_wave_repeat_forward_step =
                make_multi_index(0, 0, 0, 0, CShuffleNwaveRepeatPerShuffle, 0);
            constexpr auto n_wave_repeat_backward_step =
                make_multi_index(0, 0, 0, 0, -CShuffleNwaveRepeatPerShuffle, 0);

            static_for<0,
                       MwaveRepeat,
                       CShuffleMwaveRepeatPerShuffle>{}([&](auto m_wave_repeat_iter) {
                constexpr auto m_wave_repeat = m_wave_repeat_iter;

                static_for<0,
                           NwaveRepeat,
                           CShuffleNwaveRepeatPerShuffle>{}([&](auto n_wave_repeat_iter) {
                    constexpr bool n_wave_repeat_forward_sweep =
                        (m_wave_repeat % (2 * CShuffleMwaveRepeatPerShuffle) == 0);

                    constexpr index_t n_wave_repeat_value =
                        n_wave_repeat_forward_sweep
                            ? n_wave_repeat_iter
                            : (NwaveRepeat - n_wave_repeat_iter - CShuffleNwaveRepeatPerShuffle);

                    constexpr auto n_wave_repeat = Number<n_wave_repeat_value>{};

                    // make sure it's safe to do ds_write
                    __builtin_amdgcn_sched_barrier(0);
                    block_sync_lds();
                    __builtin_amdgcn_sched_barrier(0);

                    // VGPR to LDS
                    cshuffle_thread_copy_vgpr_to_lds.Run(
                        c_thread_desc_raw_to_interleaved,
                        make_tuple(
                            m_wave_repeat, n_wave_repeat, I0, I0, I0, I0, I0, I0, I0, I0, I0, I0),
                        c_thread_buf,
                        cshuffle_block_desc_interleaved,
                        cshuffle_block_buf);

                    // make sure it's safe to do ds_read
                    __builtin_amdgcn_sched_barrier(0);
                    block_sync_lds();
                    __builtin_amdgcn_sched_barrier(0);

                    // LDS to global
                    cshuffle_block_copy_lds_to_global.Run(cshuffle_block_desc_m0_m1_m2_n0_n1_n2,
                                                          cshuffle_block_buf,
                                                          c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                                                          c0_grid_buf,
                                                          c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                                                          c1_grid_buf,
                                                          cshuffle_grid_desc_m0_m1_m2_n0_n1_n2,
                                                          c_grid_buf);

                    // move on n_wave_repeat dimension
                    if constexpr(n_wave_repeat_forward_sweep &&
                                 (n_wave_repeat < NwaveRepeat - CShuffleNwaveRepeatPerShuffle))
                    {
                        cshuffle_block_copy_lds_to_global.MoveDstSliceWindow(
                            cshuffle_grid_desc_m0_m1_m2_n0_n1_n2, n_wave_repeat_forward_step);

                        cshuffle_block_copy_lds_to_global.MoveSrc1SliceWindow(
                            c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2, n_wave_repeat_forward_step);

                        cshuffle_block_copy_lds_to_global.MoveSrc2SliceWindow(
                            c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2, n_wave_repeat_forward_step);
                    }
                    else if constexpr((!n_wave_repeat_forward_sweep) && (n_wave_repeat > 0))
                    {
                        cshuffle_block_copy_lds_to_global.MoveDstSliceWindow(
                            cshuffle_grid_desc_m0_m1_m2_n0_n1_n2, n_wave_repeat_backward_step);

                        cshuffle_block_copy_lds_to_global.MoveSrc1SliceWindow(
                            c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2, n_wave_repeat_backward_step);

                        cshuffle_block_copy_lds_to_global.MoveSrc2SliceWindow(
                            c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2, n_wave_repeat_backward_step);
                    }
                });

                // move on m_wave_repeat dimension
                if constexpr(m_wave_repeat < MwaveRepeat - CShuffleMwaveRepeatPerShuffle)
                {
                    cshuffle_block_copy_lds_to_global.MoveDstSliceWindow(
                        cshuffle_grid_desc_m0_m1_m2_n0_n1_n2, m_wave_repeat_forward_step);

                    cshuffle_block_copy_lds_to_global.MoveSrc1SliceWindow(
                        c0shuffle_grid_desc_m0_m1_m2_n0_n1_n2, m_wave_repeat_forward_step);

                    cshuffle_block_copy_lds_to_global.MoveSrc2SliceWindow(
                        c1shuffle_grid_desc_m0_m1_m2_n0_n1_n2, m_wave_repeat_forward_step);
                }
            });
        }
    }
};

} // namespace ck
