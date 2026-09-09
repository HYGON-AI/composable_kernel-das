// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/ops/fused_conv/block/block_gemm_mmac_tn_asmem_bsmem_creg_wasp_v1.hpp"

namespace ck_tile {

struct FusedConvIgemmPipelineWaspPolicyV1
{
    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeInLdsCopyBlockDesc()
    {
        using InLayout = remove_cvref_t<typename Problem::InLayout>;

        constexpr index_t MPerWG    = Problem::MPerWG;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<InLayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, InLayout>)
        {
            constexpr auto a_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<1>{}, MPerWG, KPerBlock),
                number<Problem::InSmemLoadStoreVecLen>{});

            return a_lds_block_desc;
        }
        else
        {
            static_assert(false, "Not supported yet");
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeWeiLdsCopyBlockDesc()
    {
        using WeiLayout = remove_cvref_t<typename Problem::WeiLayout>;

        constexpr index_t NPerWG    = Problem::NPerWG;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<WeiLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, WeiLayout>)
        {
            constexpr auto b_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(number<1>{}, NPerWG, KPerBlock),
                number<Problem::WeiSmemLoadStoreVecLen>{});

            return b_lds_block_desc;
        }
        else
        {
            static_assert(false, "Not supported yet");
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeInLdsGemmBlockDesc()
    {
        using InLayout = remove_cvref_t<typename Problem::InLayout>;

        constexpr index_t MPerWG    = Problem::MPerWG;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<InLayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, InLayout>)
        {
            constexpr auto a_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(MPerWG, KPerBlock), number<Problem::InSmemLoadStoreVecLen>{});

            return a_lds_block_desc;
        }
        else
        {
            static_assert(false, "Not supported yet");
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeWeiLdsGemmBlockDesc()
    {
        using WeiLayout = remove_cvref_t<typename Problem::WeiLayout>;

        constexpr index_t NPerWG    = Problem::NPerWG;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<WeiLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, WeiLayout>)
        {
            constexpr auto b_lds_block_desc = ck_tile::make_naive_tensor_descriptor_packed(
                make_tuple(NPerWG, KPerBlock), number<Problem::WeiSmemLoadStoreVecLen>{});

            return b_lds_block_desc;
        }
        else
        {
            static_assert(false, "Not supported yet");
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetInLdsElemSize()
    {
        return ck_tile::integer_least_multiple(
            MakeInLdsGemmBlockDesc<Problem>().get_element_space_size(), Problem::KPerBlock);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetWeiLdsElemSize()
    {
        return ck_tile::integer_least_multiple(
            MakeWeiLdsGemmBlockDesc<Problem>().get_element_space_size(), Problem::KPerBlock);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetInLdsByteSize()
    {
        return GetInLdsElemSize<Problem>() * sizeof(typename Problem::InDataType);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetWeiLdsByteSize()
    {
        return GetWeiLdsElemSize<Problem>() * sizeof(typename Problem::WeiDataType);
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetLdsByteSize()
    {
        return Problem::MWGs * GetInLdsByteSize<Problem>() +
               Problem::NWGs * GetWeiLdsByteSize<Problem>();
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeInDramTileDstr()
    {
        using InLayout = remove_cvref_t<typename Problem::InLayout>;

        constexpr index_t WGSize = Problem::WGSize;

        constexpr index_t MPerWG    = Problem::MPerWG;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<InLayout, tensor_layout::convolution::NHWGC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseNGCHWc, InLayout>)
        {
            constexpr index_t ElemsTransPerLane = MPerWG * KPerBlock / WGSize;

            constexpr index_t KLaneSlice = Problem::InGmemLoadVecLen;
            constexpr index_t MLaneSlice = ElemsTransPerLane / KLaneSlice;

            constexpr index_t KLaneCluster = KPerBlock / KLaneSlice;

            if constexpr(get_warp_size() % KLaneCluster == 0)
            {
                constexpr index_t MLaneCluster = get_warp_size() / KLaneCluster;
                constexpr index_t MWarps       = WGSize / get_warp_size();

                static_assert(MLaneCluster * MWarps <= MPerWG);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<MLaneSlice, MWarps, MLaneCluster>,
                                                     sequence<KLaneCluster, KLaneSlice>>,
                                               tuple<sequence<1, 2>, sequence<2, 3>>,
                                               tuple<sequence<0, 1>, sequence<2, 0>>,
                                               sequence<2, 3>,
                                               sequence<0, 1>>{},
                    bool_constant<true>{},
                    number<Problem::SubWGSize>{});
            }
            else
            {
                static_assert(false, "Not implemented yet");
            }
        }
        else
        {
            static_assert(false, "Not implemented yet");
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto MakeWeiDramTileDstr()
    {
        using namespace ck_tile;

        using WeiLayout = remove_cvref_t<typename Problem::WeiLayout>;

        constexpr index_t WGSize = Problem::WGSize;

        constexpr index_t NPerWG    = Problem::NPerWG;
        constexpr index_t KPerBlock = Problem::KPerBlock;

        if constexpr(std::is_same_v<WeiLayout, tensor_layout::convolution::GKYXC> ||
                     std::is_base_of_v<tensor_layout::convolution::BaseGKCYXc, WeiLayout>)
        {
            constexpr index_t ElemsTransPerLane = NPerWG * KPerBlock / WGSize;

            constexpr index_t KLaneSlice = Problem::WeiGmemLoadVecLen;
            constexpr index_t NLaneSlice = ElemsTransPerLane / KLaneSlice;

            constexpr index_t KLaneCluster = KPerBlock / KLaneSlice;

            if constexpr(get_warp_size() % KLaneCluster == 0)
            {
                constexpr index_t NLaneCluster = get_warp_size() / KLaneCluster;
                constexpr index_t NWarps       = WGSize / get_warp_size();

                static_assert(NLaneCluster * NWarps <= NPerWG);

                return make_static_tile_distribution(
                    tile_distribution_encoding<sequence<1>,
                                               tuple<sequence<1>,
                                                     sequence<NLaneSlice, NWarps, NLaneCluster>,
                                                     sequence<KLaneCluster, KLaneSlice>>,
                                               tuple<sequence<1, 2>, sequence<2, 3>>,
                                               tuple<sequence<0, 1>, sequence<2, 0>>,
                                               sequence<2, 3>,
                                               sequence<0, 1>>{},
                    bool_constant<true>{},
                    number<Problem::SubWGSize>{});
            }
            else
            {
                static_assert(false, "Not implemented yet");
            }
        }
        else
        {
            static_assert(false, "Not implemented yet");
        }
    }

    template <typename Problem>
    CK_TILE_HOST_DEVICE static constexpr auto GetBlockwiseGemm()
    {
        return BlockGemmMmacTNAsmemBSmemCregWaspV1<Problem>{};
    }
};

} // namespace ck_tile
