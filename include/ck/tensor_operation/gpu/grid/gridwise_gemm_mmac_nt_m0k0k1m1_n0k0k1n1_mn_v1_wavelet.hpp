// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2023, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck/utility/amd_lds.hpp"
#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/multi_index_transform_helper.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"
#include "ck/tensor_operation/gpu/grid/block_to_ctile_map.hpp"
#include "ck/tensor_operation/gpu/grid/multistage_wavelet_pipeline.hpp"
#include "ck/tensor_operation/gpu/block/blockwise_gemm_mmac_nt_v1.hpp"
#include "ck/tensor_operation/gpu/block/thread_group_tensor_slice_transfer_lds_direct_load.hpp"
#include "ck/tensor_operation/gpu/thread/threadwise_tensor_slice_transfer.hpp"
#include "ck/tensor_operation/gpu/element/element_wise_operation.hpp"

namespace ck {

template <typename GridwiseGemm,
          typename ADataType,
          typename BDataType,
          typename CDataType,
          typename AGridDesc_B_M0_K0_K1_M1,
          typename BGridDesc_B_N0_K0_K1_N1,
          typename CGridDescInterleaved,
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
    kernel_gemm_mmac(const ADataType* __restrict__ p_a_grid,
                     const BDataType* __restrict__ p_b_grid,
                     CDataType* __restrict__ p_c_grid,
                     const AGridDesc_B_M0_K0_K1_M1 a_grid_desc_b_m0_k0_k1_m1,
                     const BGridDesc_B_N0_K0_K1_N1 b_grid_desc_b_n0_k0_k1_n1,
                     const CGridDescInterleaved c_grid_desc_interleaved,
                     const AElementwiseOperation a_element_op,
                     const BElementwiseOperation b_element_op,
                     const CElementwiseOperation c_element_op,
                     const Block2CTileMap block_2_ctile_map)
{
#if(!defined(__HIP_DEVICE_COMPILE__) || defined(__gfx926__) || defined(__gfx928__) || defined(__gfx92a__) || \
    defined(__gfx936__) || defined(__gfx938__))
    __shared__ char p_shared[GridwiseGemm::GetSharedMemoryNumberOfByte()];

    GridwiseGemm::template Run<HasMainKBlockLoop>(p_a_grid,
                                                  p_b_grid,
                                                  p_c_grid,
                                                  p_shared,
                                                  a_grid_desc_b_m0_k0_k1_m1,
                                                  b_grid_desc_b_n0_k0_k1_n1,
                                                  c_grid_desc_interleaved,
                                                  a_element_op,
                                                  b_element_op,
                                                  c_element_op,
                                                  block_2_ctile_map);
#else
    ignore = p_a_grid;
    ignore = p_b_grid;
    ignore = p_c_grid;
    ignore = a_grid_desc_b_m0_k0_k1_m1;
    ignore = b_grid_desc_b_n0_k0_k1_n1;
    ignore = c_grid_desc_interleaved;
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
          InMemoryDataOperationEnum CGlobalMemoryDataOperation,
          typename AElementwiseOperation,
          typename BElementwiseOperation,
          typename CElementwiseOperation,
          typename AGridDesc_B_M0_K0_K1_M1,
          typename BGridDesc_B_N0_K0_K1_N1,
          typename CGridDesc_M_N,
          index_t M0PerBlock,
          index_t M1PerBlock,
          index_t N0PerBlock,
          index_t N1PerBlock,
          index_t K0PerBlock,
          index_t K1PerBlock,
          index_t MPerMmac,
          index_t NPerMmac,
          index_t MwaveRepeat,
          index_t NwaveRepeat,
          index_t MmmacRepeat,
          index_t NmmacRepeat,
          index_t MmmacInterleave,
          index_t NmmacInterleave,
          typename ABlockTransferThreadClusterLengths_B_M0_K0_K1_M1,
          index_t ABlockTransferSrcVectorDim,
          index_t ABlockTransferSrcScalarPerVector,
          typename BBlockTransferThreadClusterLengths_B_N0_K0_K1_N1,
          index_t BBlockTransferSrcVectorDim,
          index_t BBlockTransferSrcScalarPerVector,
          index_t CThreadTransferDstScalarPerVector,
          index_t NumGemmKPrefetchStage>
struct GridwiseGemm_mmac_nt_m0k0k1m1_n0k0k1n1_mn_v1_wavelet
{
    // A/B elementwise operation not supported
    static_assert(
        is_same_v<AElementwiseOperation, ck::tensor_operation::element_wise::PassThrough>);
    static_assert(
        is_same_v<BElementwiseOperation, ck::tensor_operation::element_wise::PassThrough>);

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

    static constexpr index_t MPerBlock = M0PerBlock * M1PerBlock;
    static constexpr index_t NPerBlock = N0PerBlock * N1PerBlock;
    static constexpr index_t KPerBlock = K0PerBlock * K1PerBlock;

    static constexpr auto ABlockTransReadSize =
        sizeof(ADataType) * ABlockTransferSrcScalarPerVector;
    static constexpr auto BBlockTransReadSize =
        sizeof(BDataType) * BBlockTransferSrcScalarPerVector;

    static constexpr index_t DirectLoadIssueA =
        (MPerBlock * KPerBlock / BlockSize) * sizeof(ADataType) / ABlockTransReadSize;
    static constexpr index_t DirectLoadIssueB =
        (NPerBlock * KPerBlock / BlockSize) * sizeof(BDataType) / BBlockTransReadSize;

    static constexpr index_t DirectLoadIssuePerStage = DirectLoadIssueA + DirectLoadIssueB;

    // at least 2 wave is needed
    static_assert(BlockSize % 128 == 0);
    static constexpr auto TileLoadThreadGroupSize = BlockSize / 2;
    static constexpr auto TileMathThreadGroupSize = BlockSize / 2;

    using WaveletTG = WaveletThreadGroup<TileLoadThreadGroupSize, TileMathThreadGroupSize>;

    using ThisThreadBlock = ThisThreadBlock<BlockSize>;

    using MultiStagePipeline = remove_cvref_t<
        decltype(MultiStageWaveletPipeline<NumGemmKPrefetchStage, DirectLoadIssuePerStage>())>;

    using AStorageType = typename storage_type<ADataType>::type;
    using BStorageType = typename storage_type<BDataType>::type;

    __host__ __device__ static constexpr auto
    GetABlockDescriptor_M0PerBlock_K0PerBlock_K1PerBlock_M1PerBlock()
    {

        return make_naive_tensor_descriptor_packed(make_tuple(Number<M0PerBlock>{},
                                                              Number<K0PerBlock>{},
                                                              Number<K1PerBlock>{},
                                                              Number<M1PerBlock>{}));
    }

    __host__ __device__ static constexpr auto
    GetBBlockDescriptor_N0PerBlock_K0PerBlock_K1PerBlock_N1PerBlock()
    {

        return make_naive_tensor_descriptor_packed(make_tuple(Number<N0PerBlock>{},
                                                              Number<K0PerBlock>{},
                                                              Number<K1PerBlock>{},
                                                              Number<N1PerBlock>{}));
    }

    __host__ __device__ static constexpr auto
    GetABlockDescriptor_B_M0PerBlock_K0PerBlock_K1PerBlock_M1PerBlock()
    {

        return make_naive_tensor_descriptor_packed(make_tuple(Number<1>{},
                                                              Number<M0PerBlock>{},
                                                              Number<K0PerBlock>{},
                                                              Number<K1PerBlock>{},
                                                              Number<M1PerBlock>{}));
    }

    __host__ __device__ static constexpr auto
    GetBBlockDescriptor_B_N0PerBlock_K0PerBlock_K1PerBlock_N1PerBlock()
    {

        return make_naive_tensor_descriptor_packed(make_tuple(Number<1>{},
                                                              Number<N0PerBlock>{},
                                                              Number<K0PerBlock>{},
                                                              Number<K1PerBlock>{},
                                                              Number<N1PerBlock>{}));
    }

    __host__ __device__ static constexpr index_t GetSharedMemoryNumberOfByte()
    {
        // LDS allocation for A and B: be careful of alignment
        constexpr auto a_block_desc =
            GetABlockDescriptor_M0PerBlock_K0PerBlock_K1PerBlock_M1PerBlock();

        constexpr auto b_block_desc =
            GetBBlockDescriptor_N0PerBlock_K0PerBlock_K1PerBlock_N1PerBlock();

        constexpr auto a_block_space_size_aligned =
            math::integer_least_multiple(a_block_desc.GetElementSpaceSize(), Number<M1PerBlock>{});

        constexpr auto b_block_space_size_aligned =
            math::integer_least_multiple(b_block_desc.GetElementSpaceSize(), Number<N1PerBlock>{});

        return (NumGemmKPrefetchStage * a_block_space_size_aligned * sizeof(AStorageType) +
                NumGemmKPrefetchStage * b_block_space_size_aligned * sizeof(BStorageType));
    }

    // block_id to matrix tile idx (m0, n0) mapping are controlled by {M01, N01}
    template <typename Block2CTileMap>
    __host__ __device__ static constexpr bool
    CheckValidity(const AGridDesc_B_M0_K0_K1_M1& a_grid_desc_b_m0_k0_k1_m1,
                  const BGridDesc_B_N0_K0_K1_N1& b_grid_desc_b_n0_k0_k1_n1,
                  const CGridDesc_M_N& c_grid_desc_m_n,
                  const Block2CTileMap& block_2_ctile_map)
    {
        static_assert((MPerBlock % (MwaveRepeat * MmmacRepeat * MPerMmac * MmmacInterleave) == 0) &&
                          (NPerBlock % (NwaveRepeat * NmmacRepeat * NPerMmac * NmmacInterleave)) ==
                              0,
                      "Invalid tuning param!");

        const auto M =
            a_grid_desc_b_m0_k0_k1_m1.GetLength(I1) * a_grid_desc_b_m0_k0_k1_m1.GetLength(I4);
        const auto N =
            b_grid_desc_b_n0_k0_k1_n1.GetLength(I1) * b_grid_desc_b_n0_k0_k1_n1.GetLength(I4);
        const auto K0 = a_grid_desc_b_m0_k0_k1_m1.GetLength(I2);

        if(!(M % MPerBlock == 0 && N % NPerBlock == 0 && K0 % K0PerBlock == 0))
            return false;

        // check gridwise gemm pipeline
        const auto num_k_loop = K0 / K0PerBlock;

        if(!MultiStagePipeline::IsSupported(num_k_loop))
        {
            return false;
        }

        if(!block_2_ctile_map.CheckValidity(c_grid_desc_m_n))
        {
            return false;
        }

        // TODO: also check validity of all components (blockwise-copy, threadwise-copy, etc)
        return true;
    }

    __host__ __device__ static constexpr bool CalculateHasMainKBlockLoop(index_t K)
    {
        const index_t num_loop = K / (K0PerBlock * K1PerBlock);

        return MultiStagePipeline::CalculateHasMainLoop(num_loop);
    }

    __host__ __device__ static constexpr auto
    MakeCGridDescriptorInterleaved12D(const CGridDesc_M_N& c_grid_desc_m_n)
    {
        // A matrix in LDS memory, dst of blockwise copy
        constexpr auto a_block_desc =
            GetABlockDescriptor_M0PerBlock_K0PerBlock_K1PerBlock_M1PerBlock();

        // B matrix in LDS memory, dst of blockwise copy
        constexpr auto b_block_desc =
            GetBBlockDescriptor_N0PerBlock_K0PerBlock_K1PerBlock_N1PerBlock();

        using BlockwiseGemm = BlockwiseGemmASmemBSmemCReg_mmac_nt_m0k0k1m1_n0k0k1n1_mn_v1<
            TileMathThreadGroupSize,
            ADataType,
            BDataType,
            AccDataType,
            decltype(a_block_desc),
            decltype(b_block_desc),
            sizeof(ADataType) * ABlockTransferSrcScalarPerVector,
            sizeof(BDataType) * BBlockTransferSrcScalarPerVector,
            MPerMmac,
            NPerMmac,
            MwaveRepeat,
            NwaveRepeat,
            MmmacRepeat,
            NmmacRepeat,
            MmmacInterleave,
            NmmacInterleave,
            NumGemmKPrefetchStage,
            true>;

        return BlockwiseGemm::MakeCGridDescriptorInterleaved12D(c_grid_desc_m_n);
    }

    // return block_id to C matrix tile idx (m0, n0) mapping
    __host__ __device__ static constexpr auto MakeDefaultBlock2CTileMap(
        const CGridDesc_M_N& c_grid_desc_m_n, index_t M01, index_t N01, index_t KBatch)
    {
        return BlockToCTileMap_KSplit_M00_N00_M01_N01<MPerBlock, NPerBlock, CGridDesc_M_N>(
            c_grid_desc_m_n, M01, N01, KBatch);
    }

    using CGridDescInterleaved  = decltype(MakeCGridDescriptorInterleaved12D(CGridDesc_M_N{}));
    using DefaultBlock2CTileMap = decltype(MakeDefaultBlock2CTileMap(CGridDesc_M_N{}, 1, 1, 1));

    template <bool HasMainKBlockLoop, typename Block2CTileMap = DefaultBlock2CTileMap>
    __device__ static void Run(const ADataType* __restrict__ p_a_grid,
                               const BDataType* __restrict__ p_b_grid,
                               CDataType* __restrict__ p_c_grid,
                               void* __restrict__ p_shared,
                               const AGridDesc_B_M0_K0_K1_M1& a_grid_desc_b_m0_k0_k1_m1,
                               const BGridDesc_B_N0_K0_K1_N1& b_grid_desc_b_n0_k0_k1_n1,
                               const CGridDescInterleaved& c_grid_desc_interleaved,
                               const AElementwiseOperation& /*a_element_op*/,
                               const BElementwiseOperation& /*b_element_op*/,
                               const CElementwiseOperation& c_element_op,
                               const Block2CTileMap& block_2_ctile_map)
    {
        const auto a_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            reinterpret_cast<const AStorageType*>(p_a_grid),
            a_grid_desc_b_m0_k0_k1_m1.GetElementSpaceSize());
        const auto b_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            reinterpret_cast<const BStorageType*>(p_b_grid),
            b_grid_desc_b_n0_k0_k1_n1.GetElementSpaceSize());

        auto c_grid_buf = make_dynamic_buffer<AddressSpaceEnum::Global>(
            p_c_grid, c_grid_desc_interleaved.GetElementSpaceSize());

        // divide block work by [M, N]
        const auto block_work_idx =
            block_2_ctile_map.CalculateBottomIndex(make_multi_index(get_block_1d_id()));

        if(!block_2_ctile_map.ValidCTileIndex(block_work_idx,
                                              make_tuple(c_grid_desc_interleaved.GetLength(I0),
                                                         c_grid_desc_interleaved.GetLength(I1))))
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
        constexpr auto a_block_desc_m0_k0_k1_m1 =
            GetABlockDescriptor_M0PerBlock_K0PerBlock_K1PerBlock_M1PerBlock();

        constexpr auto a_block_desc_b_m0_k0_k1_m1 =
            GetABlockDescriptor_B_M0PerBlock_K0PerBlock_K1PerBlock_M1PerBlock();

        // B matrix in LDS memory, dst of blockwise copy
        constexpr auto b_block_desc_n0_k0_k1_n1 =
            GetBBlockDescriptor_N0PerBlock_K0PerBlock_K1PerBlock_N1PerBlock();

        constexpr auto b_block_desc_b_n0_k0_k1_n1 =
            GetBBlockDescriptor_B_N0PerBlock_K0PerBlock_K1PerBlock_N1PerBlock();

        // LDS allocation for A and B: be careful of alignment
        constexpr auto a_block_space_size_aligned = math::integer_least_multiple(
            a_block_desc_m0_k0_k1_m1.GetElementSpaceSize(), Number<M1PerBlock>{});

        constexpr auto a_block_bufs_offset = 0;
        auto a_block_bufs = ck::lds_utils::AllocateLdsBuffers<ADataType, NumGemmKPrefetchStage>(
            p_shared,
            a_block_desc_m0_k0_k1_m1.GetElementSpaceSize(),
            a_block_bufs_offset,
            Number<M1PerBlock>{});

        constexpr auto b_block_bufs_offset = a_block_space_size_aligned * NumGemmKPrefetchStage;
        auto b_block_bufs = ck::lds_utils::AllocateLdsBuffers<BDataType, NumGemmKPrefetchStage>(
            p_shared,
            b_block_desc_n0_k0_k1_n1.GetElementSpaceSize(),
            b_block_bufs_offset,
            Number<N1PerBlock>{});

        // gridwise GEMM pipeline
        const auto K0          = a_grid_desc_b_m0_k0_k1_m1.GetLength(I2);
        const index_t num_loop = __builtin_amdgcn_readfirstlane(K0 / K0PerBlock);

        if(WaveletTG::IsLoadGroup())
        {
            constexpr auto a_block_slice_copy_step = make_multi_index(0, 0, K0PerBlock, 0, 0);
            constexpr auto b_block_slice_copy_step = make_multi_index(0, 0, K0PerBlock, 0, 0);

            // A matrix blockwise copy
            auto a_blockwise_copy = ThreadGroupTensorSliceTransfer_DirectLoad<
                typename WaveletTG::TileLoadThreadGroup,
                Sequence<1, M0PerBlock, K0PerBlock, K1PerBlock, M1PerBlock>,
                ABlockTransferThreadClusterLengths_B_M0_K0_K1_M1,
                ADataType,
                ADataType,
                decltype(a_grid_desc_b_m0_k0_k1_m1),
                decltype(a_block_desc_b_m0_k0_k1_m1),
                ABlockTransferSrcVectorDim,
                ABlockTransferSrcVectorDim,
                ABlockTransferSrcScalarPerVector>(
                a_grid_desc_b_m0_k0_k1_m1,
                make_multi_index(k_batch_id, m_block_data_idx_on_grid / M1PerBlock, 0, 0, 0),
                a_block_desc_b_m0_k0_k1_m1,
                make_multi_index(0, 0, 0, 0, 0));

            // B matrix blockwise copy
            auto b_blockwise_copy = ThreadGroupTensorSliceTransfer_DirectLoad<
                typename WaveletTG::TileLoadThreadGroup,
                Sequence<1, N0PerBlock, K0PerBlock, K1PerBlock, N1PerBlock>,
                BBlockTransferThreadClusterLengths_B_N0_K0_K1_N1,
                BDataType,
                BDataType,
                decltype(b_grid_desc_b_n0_k0_k1_n1),
                decltype(b_block_desc_b_n0_k0_k1_n1),
                BBlockTransferSrcVectorDim,
                BBlockTransferSrcVectorDim,
                BBlockTransferSrcScalarPerVector>(
                b_grid_desc_b_n0_k0_k1_n1,
                make_multi_index(k_batch_id, n_block_data_idx_on_grid / N1PerBlock, 0, 0, 0),
                b_block_desc_b_n0_k0_k1_n1,
                make_multi_index(0, 0, 0, 0, 0));

            MultiStagePipeline::template RunLoadPipeline<HasMainKBlockLoop>(
                a_grid_desc_b_m0_k0_k1_m1,
                a_block_desc_b_m0_k0_k1_m1,
                a_blockwise_copy,
                a_grid_buf,
                a_block_bufs,
                a_block_slice_copy_step,
                b_grid_desc_b_n0_k0_k1_n1,
                b_block_desc_b_n0_k0_k1_n1,
                b_blockwise_copy,
                b_grid_buf,
                b_block_bufs,
                b_block_slice_copy_step,
                num_loop);
        }
        else if(WaveletTG::IsMathGroup())
        {

            auto blockwise_gemm = BlockwiseGemmASmemBSmemCReg_mmac_nt_m0k0k1m1_n0k0k1n1_mn_v1<
                TileMathThreadGroupSize,
                ADataType,
                BDataType,
                AccDataType,
                decltype(a_block_desc_m0_k0_k1_m1),
                decltype(b_block_desc_n0_k0_k1_n1),
                sizeof(ADataType) * ABlockTransferSrcScalarPerVector,
                sizeof(BDataType) * BBlockTransferSrcScalarPerVector,
                MPerMmac,
                NPerMmac,
                MwaveRepeat,
                NwaveRepeat,
                MmmacRepeat,
                NmmacRepeat,
                MmmacInterleave,
                NmmacInterleave,
                NumGemmKPrefetchStage,
                HasMainKBlockLoop>();

            auto c_thread_buf = blockwise_gemm.GetCThreadBuffer();

            MultiStagePipeline::template RunMathPipeline<HasMainKBlockLoop>(
                blockwise_gemm, a_block_bufs, b_block_bufs, c_thread_buf, num_loop);

            // output: register to global memory
            {
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

                // calculate origin of thread output tensor on global memory
                //     blockwise GEMM c matrix starting index
                const auto c_thread_mtx_on_block =
                    blockwise_gemm.CalculateCThreadOriginDataIndex(I0, I0, I0, I0);

                const index_t m_thread_data_on_grid =
                    m_block_data_idx_on_grid + c_thread_mtx_on_block[I0];

                const index_t n_thread_data_on_grid =
                    n_block_data_idx_on_grid + c_thread_mtx_on_block[I1];

                const auto m_thread_data_on_grid_to_m0_m1_m2_m3_m4_m5_m6_adaptor =
                    make_single_stage_tensor_adaptor(
                        make_tuple(make_merge_transform(make_tuple(M0, M1, M2, M3, M4, M5, M6))),
                        make_tuple(Sequence<0, 1, 2, 3, 4, 5, 6>{}),
                        make_tuple(Sequence<0>{}));

                const auto m_thread_data_on_grid_idx =
                    m_thread_data_on_grid_to_m0_m1_m2_m3_m4_m5_m6_adaptor.CalculateBottomIndex(
                        make_multi_index(m_thread_data_on_grid));

                const auto n_thread_data_on_grid_to_n0_n1_n2_n3_n4_adaptor =
                    make_single_stage_tensor_adaptor(
                        make_tuple(make_merge_transform(make_tuple(N0, N1, N2, N3, N4))),
                        make_tuple(Sequence<0, 1, 2, 3, 4>{}),
                        make_tuple(Sequence<0>{}));

                const auto n_thread_data_on_grid_idx =
                    n_thread_data_on_grid_to_n0_n1_n2_n3_n4_adaptor.CalculateBottomIndex(
                        make_multi_index(n_thread_data_on_grid));

                auto c_thread_copy_vgpr_to_global = ThreadwiseTensorSliceTransfer_v1r3<
                    AccDataType,
                    CDataType,
                    decltype(c_thread_desc_raw_to_interleaved),
                    decltype(c_grid_desc_interleaved),
                    CElementwiseOperation,
                    Sequence<M0, N0, I1, I1, M2, N2, M3, I1, M5, M6, I1, N4>,
                    Sequence<0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11>,
                    11,
                    CThreadTransferDstScalarPerVector,
                    CGlobalMemoryDataOperation,
                    1,
                    true>{c_grid_desc_interleaved,
                          make_multi_index(m_thread_data_on_grid_idx[I0],
                                           n_thread_data_on_grid_idx[I0],
                                           m_thread_data_on_grid_idx[I1],
                                           n_thread_data_on_grid_idx[I1],
                                           m_thread_data_on_grid_idx[I2],
                                           n_thread_data_on_grid_idx[I2],
                                           m_thread_data_on_grid_idx[I3],
                                           m_thread_data_on_grid_idx[I4],
                                           m_thread_data_on_grid_idx[I5],
                                           m_thread_data_on_grid_idx[I6],
                                           n_thread_data_on_grid_idx[I3],
                                           n_thread_data_on_grid_idx[I4]),
                          c_element_op};

                c_thread_copy_vgpr_to_global.Run(
                    c_thread_desc_raw_to_interleaved,
                    make_tuple(I0, I0, I0, I0, I0, I0, I0, I0, I0, I0, I0, I0),
                    c_thread_buf,
                    c_grid_desc_interleaved,
                    c_grid_buf);
            }
        }
    }
};

} // namespace ck
