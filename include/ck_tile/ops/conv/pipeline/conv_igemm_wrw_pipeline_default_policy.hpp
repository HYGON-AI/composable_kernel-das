// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/conv/block/block_gemm_mmac_nt_asmem_bsmem_creg_v1.hpp"

namespace ck_tile {

struct ConvIgemmWrwPipelineDefaultPolicy
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
                make_tuple(number<1>{}, KPerBlock, MPerBlock),
                number<Problem::ASmemStoreVectorLength>{});

            return transform_tensor_descriptor(
                a_lds_block_desc,
                make_tuple(make_pass_through_transform(number<1>{}),
                           make_pass_through_transform(KPerBlock),
                           make_pass_through_transform(MPerBlock)),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}),
                make_tuple(sequence<0>{}, sequence<2>{}, sequence<1>{}));
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
                make_tuple(number<1>{}, KPerBlock, NPerBlock),
                number<Problem::BSmemStoreVectorLength>{});

            return transform_tensor_descriptor(
                b_lds_block_desc,
                make_tuple(make_pass_through_transform(number<1>{}),
                           make_pass_through_transform(KPerBlock),
                           make_pass_through_transform(NPerBlock)),
                make_tuple(sequence<0>{}, sequence<1>{}, sequence<2>{}),
                make_tuple(sequence<0>{}, sequence<2>{}, sequence<1>{}));
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
                make_tuple(KPerBlock, MPerBlock), number<Problem::ASmemLoadVectorLength>{});

            return transform_tensor_descriptor(a_lds_block_desc,
                                               make_tuple(make_pass_through_transform(KPerBlock),
                                                          make_pass_through_transform(MPerBlock)),
                                               make_tuple(sequence<0>{}, sequence<1>{}),
                                               make_tuple(sequence<1>{}, sequence<0>{}));
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
                make_tuple(KPerBlock, NPerBlock), number<Problem::BSmemLoadVectorLength>{});

            return transform_tensor_descriptor(b_lds_block_desc,
                                               make_tuple(make_pass_through_transform(KPerBlock),
                                                          make_pass_through_transform(NPerBlock)),
                                               make_tuple(sequence<0>{}, sequence<1>{}),
                                               make_tuple(sequence<1>{}, sequence<0>{}));
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

        return ck_tile::integer_least_multiple(smem_size_a, Problem::MPerBlock);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr index_t GetAlignedSmemSizeB()
    {
        constexpr index_t smem_size_b =
            MakeBLdsGemmBlockDescriptor<Problem>().get_element_space_size();

        return ck_tile::integer_least_multiple(smem_size_b, Problem::NPerBlock);
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
            constexpr index_t TotalPixelsPerLane = MPerBlock * KPerBlock / BlockSize;

            constexpr index_t KLaneSlice = Problem::AGmemLoadVectorLength;
            constexpr index_t MLaneSlice = TotalPixelsPerLane / KLaneSlice;

            constexpr index_t KLaneCluster = KPerBlock / KLaneSlice;

            if constexpr(get_warp_size() % KLaneCluster == 0)
            {
                constexpr index_t MLaneCluster = get_warp_size() / KLaneCluster;
                constexpr index_t MWarps       = BlockSize / get_warp_size();

                static_assert(MLaneCluster * MWarps <= MPerBlock);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<MLaneSlice, MWarps, MLaneCluster>,
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

#if 0

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
            constexpr index_t TotalPixelsPerLane = MPerBlock * KPerBlock / BlockSize;

            constexpr index_t MLaneSlice = Problem::AGmemLoadVectorLength;
            constexpr index_t KLaneSlice = TotalPixelsPerLane / MLaneSlice;

            constexpr index_t MLaneCluster = MPerBlock / MLaneSlice;

            if constexpr(get_warp_size() % MLaneCluster == 0)
            {
                constexpr index_t KLaneCluster = get_warp_size() / MLaneCluster;
                constexpr index_t KWarps       = BlockSize / get_warp_size();

                static_assert(KLaneCluster * KWarps <= KPerBlock);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<MLaneSlice, MLaneCluster>,
                                                     sequence<KLaneCluster, KWarps, KLaneSlice>>,
                                               tuple<sequence<1, 3>, sequence<3, 2>>,
                                               tuple<sequence<0, 1>, sequence<0, 1>>,
                                               sequence<3, 2>,
                                               sequence<2, 0>>{});
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

            constexpr index_t NLaneSlice = Problem::BGmemLoadVectorLength;
            constexpr index_t KLaneSlice = TotalPixelsPerLane / NLaneSlice;

            constexpr index_t NLaneCluster = NPerBlock / NLaneSlice;

            if constexpr(get_warp_size() % NLaneCluster == 0)
            {
                constexpr index_t KLaneCluster = get_warp_size() / NLaneCluster;
                constexpr index_t KWarps       = BlockSize / get_warp_size();

                static_assert(KLaneCluster * KWarps <= KPerBlock);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<NLaneSlice, NLaneCluster>,
                                                     sequence<KLaneCluster, KWarps, KLaneSlice>>,
                                               tuple<sequence<1, 3>, sequence<3, 2>>,
                                               tuple<sequence<0, 1>, sequence<0, 1>>,
                                               sequence<3, 2>,
                                               sequence<2, 0>>{});
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
#endif

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetBlockwiseGemm()
    {
        return BlockGemmMmacNTAsmemBSmemCregV1<Problem>{};
    }
};

} // namespace ck_tile
