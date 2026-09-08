// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv/block/block_gemm_mmac_tn_asmem_bsmem_creg_v1.hpp"

namespace ck_tile {

struct ConvIgemmFwdPipelineDefaultPolicy
{
    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeALdsCopyBlockDescriptor()
    {
        using ALayout = remove_cvref_t<typename Problem::ALayout>;

        constexpr index_t MPerBlock = Problem::MPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<ALayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, ALayout>)
        {
            // TODO: how to support lds swizzle in ck_tile?
            constexpr auto a_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<1>{}, MPerBlock, KPerBlock),
                number<Problem::ASmemStoreVectorLength>{});

            return a_lds_block_desc;
        }
        else
        {
            // TODO: NGCHW here?
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBLdsCopyBlockDescriptor()
    {
        using BLayout = remove_cvref_t<typename Problem::BLayout>;

        constexpr index_t NPerBlock = Problem::NPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<BLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, BLayout>)
        {
            constexpr auto b_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<1>{}, NPerBlock, KPerBlock),
                number<Problem::BSmemStoreVectorLength>{});

            return b_lds_block_desc;
        }
        else
        {
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeALdsGemmBlockDescriptor()
    {
        using ALayout = remove_cvref_t<typename Problem::ALayout>;

        constexpr index_t MPerBlock = Problem::MPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<ALayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, ALayout>)
        {
            // TODO: how to support lds swizzle in ck_tile?
            constexpr auto a_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(MPerBlock, KPerBlock), number<Problem::ASmemLoadVectorLength>{});

            return a_lds_block_desc;
        }
        else
        {
            // TODO: NGCHW here?
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBLdsGemmBlockDescriptor()
    {
        using BLayout = remove_cvref_t<typename Problem::BLayout>;

        constexpr index_t NPerBlock = Problem::NPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<BLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, BLayout>)
        {
            constexpr auto b_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(NPerBlock, KPerBlock), number<Problem::BSmemLoadVectorLength>{});

            return b_lds_block_desc;
        }
        else
        {
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeALdsAsyncCopyBlockDescriptor()
    {
        using ALayout = remove_cvref_t<typename Problem::ALayout>;

        constexpr index_t MPerBlock = Problem::MPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        constexpr index_t KVectorLength = Problem::ASmemStoreVectorLength;
        constexpr index_t KLane         = KPerBlock / KVectorLength;
        constexpr index_t MLane         = get_warp_size() / KLane;

        constexpr index_t NumIssue = (MPerBlock * KPerBlock) / (Problem::BlockSize * KVectorLength);
        constexpr index_t NumWarps = Problem::BlockSize / get_warp_size();

        if constexpr(std::is_same_v<ALayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, ALayout>)
        {
            // TODO: how to support lds swizzle in ck_tile?
            constexpr auto a_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<MPerBlock>{}, number<KPerBlock>{}),
                number<Problem::ASmemStoreVectorLength>{});

            constexpr auto a_lds_block_desc_unmerged = transform_tensor_descriptor(
                a_lds_block_desc,
                make_tuple(
                    make_unmerge_transform(
                        make_tuple(number<NumIssue>{}, number<NumWarps>{}, number<MLane>{})),
                    make_unmerge_transform(make_tuple(number<KLane>{}, number<KVectorLength>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}),
                make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}));

            return transform_tensor_descriptor(
                a_lds_block_desc_unmerged,
                make_tuple(make_pass_through_transform(number<NumIssue>{}),
                           make_pass_through_transform(number<NumWarps>{}),
                           make_merge_transform(make_tuple(
                               number<MLane>{}, number<KLane>{}, number<KVectorLength>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2, 3, 4>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}));
        }
        else
        {
            // TODO: NGCHW here?
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBLdsAsyncCopyBlockDescriptor()
    {
        using BLayout = remove_cvref_t<typename Problem::BLayout>;

        constexpr index_t NPerBlock = Problem::NPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        constexpr index_t KVectorLength = Problem::ASmemStoreVectorLength;
        constexpr index_t KLane         = KPerBlock / KVectorLength;
        constexpr index_t NLane         = get_warp_size() / KLane;

        constexpr index_t NumIssue = (NPerBlock * KPerBlock) / (Problem::BlockSize * KVectorLength);
        constexpr index_t NumWarps = Problem::BlockSize / get_warp_size();

        if constexpr(std::is_same_v<BLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, BLayout>)
        {
            // TODO: how to support lds swizzle in ck_tile?
            constexpr auto b_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<NPerBlock>{}, number<KPerBlock>{}),
                number<Problem::BSmemStoreVectorLength>{});

            constexpr auto b_lds_block_desc_unmerged = transform_tensor_descriptor(
                b_lds_block_desc,
                make_tuple(
                    make_unmerge_transform(
                        make_tuple(number<NumIssue>{}, number<NumWarps>{}, number<NLane>{})),
                    make_unmerge_transform(make_tuple(number<KLane>{}, number<KVectorLength>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}),
                make_tuple(sequence<0, 1, 2>{}, sequence<3, 4>{}));

            return transform_tensor_descriptor(
                b_lds_block_desc_unmerged,
                make_tuple(make_pass_through_transform(number<NumIssue>{}),
                           make_pass_through_transform(number<NumWarps>{}),
                           make_merge_transform(make_tuple(
                               number<NLane>{}, number<KLane>{}, number<KVectorLength>{}))),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2, 3, 4>{}),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}));
        }
        else
        {
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr index_t GetAlignedSmemSizeA()
    {
        constexpr index_t smem_size_a =
            MakeALdsGemmBlockDescriptor<Problem>().get_element_space_size();

        return ck_tile::integer_least_multiple(smem_size_a, Problem::KPerBlock);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr index_t GetAlignedSmemSizeB()
    {
        constexpr index_t smem_size_b =
            MakeBLdsGemmBlockDescriptor<Problem>().get_element_space_size();

        return ck_tile::integer_least_multiple(smem_size_b, Problem::KPerBlock);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr index_t GetAlignedSmemByteSize()
    {
        return Problem::NumPrefetch *
               (GetAlignedSmemSizeA<Problem>() * sizeof(typename Problem::ADataType) +
                GetAlignedSmemSizeB<Problem>() * sizeof(typename Problem::BDataType));
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeADramTileDistribution()
    {
        using namespace ck_tile;

        using ALayout = remove_cvref_t<typename Problem::ALayout>;

        constexpr index_t BlockSize = Problem::BlockSize;

        constexpr index_t MPerBlock = Problem::MPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<ALayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, ALayout>)
        {
            constexpr index_t TotalPixelsPerLane = MPerBlock * KPerBlock / BlockSize; // 64*16/16 

            constexpr index_t KLaneSlice = Problem::AGmemLoadVectorLength; // 4
            constexpr index_t MLaneSlice = TotalPixelsPerLane / KLaneSlice; // 256/4 

            constexpr index_t KLaneCluster = KPerBlock / KLaneSlice; //16 / 4 4

            if constexpr(get_warp_size() % KLaneCluster == 0)
            {
                constexpr index_t MLaneCluster = get_warp_size() / KLaneCluster;
                constexpr index_t MWarps       = BlockSize / get_warp_size();

                static_assert(MLaneCluster * MWarps <= MPerBlock);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<MLaneSlice, MWarps, MLaneCluster>, /// <64, 4, 4>
                                                     sequence<KLaneCluster, KLaneSlice>>, /// <4,4>
                                               tuple<sequence<1, 2>, sequence<2, 3>>, /// <<>>
                                               tuple<sequence<0, 1>, sequence<2, 0>>,
                                               sequence<2, 3>,
                                               sequence<0, 1>>{});
            }
            else
            {
                static_assert(false);
            }
        }
        else
        {
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeBDramTileDistribution()
    {
        using namespace ck_tile;

        using BLayout = remove_cvref_t<typename Problem::BLayout>;

        constexpr index_t BlockSize = Problem::BlockSize;

        constexpr index_t NPerBlock = Problem::NPerBlock;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<BLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, BLayout>)
        {
            constexpr index_t TotalPixelsPerLane = NPerBlock * KPerBlock / BlockSize;

            constexpr index_t KLaneSlice = Problem::BGmemLoadVectorLength;
            constexpr index_t NLaneSlice = TotalPixelsPerLane / KLaneSlice;

            constexpr index_t KLaneCluster = KPerBlock / KLaneSlice;

            if constexpr(get_warp_size() % KLaneCluster == 0)
            {
                constexpr index_t NLaneCluster = get_warp_size() / KLaneCluster;
                constexpr index_t NWarps       = BlockSize / get_warp_size();

                static_assert(NLaneCluster * NWarps <= NPerBlock);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<NLaneSlice, NWarps, NLaneCluster>,
                                                     sequence<KLaneCluster, KLaneSlice>>,
                                               tuple<sequence<1, 2>, sequence<2, 3>>,
                                               tuple<sequence<0, 1>, sequence<2, 0>>,
                                               sequence<2, 3>,
                                               sequence<0, 1>>{});
            }
            else
            {
                static_assert(false);
            }
        }
        else
        {
            static_assert(false);
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetBlockwiseGemm()
    {
        return BlockGemmMmacTNAsmemBSmemCregV1<Problem>{};
    }
};

} // namespace ck_tile
