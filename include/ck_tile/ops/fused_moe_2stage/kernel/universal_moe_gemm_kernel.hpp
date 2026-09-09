// SPDX-License-Identifier: MIT
// Copyright (c) 2025, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#pragma once

#include <iostream>
#include <string>
#include <type_traits>

#include "ck_tile/core.hpp"
#include "ck_tile/ops/common.hpp"
#include "ck_tile/host/concat.hpp"
#include "ck_tile/host/kernel_launch.hpp"
#include "ck_tile/host/stream_utils.hpp"
#include "ck_tile/core/utility/env.hpp"
#include "ck_tile/core/utility/type_traits.hpp"
#include "ck_tile/ops/common/utils.hpp" 

namespace ck_tile {

/// @brief The Universal GEMM kernel host arguments.
///
/// @par Overview
///      This structure is passed to @ref UniversalMoeGemmKernel "UniversalMoeGemmKernel" when creating
///      kernel arguments object. It contain all necessary information required to build proper
///      kernel argument and launch kernel on GPU. This structure defines the GEMM problem
///      configuration by stating all required information like M,N,K sizes and respective strides.
///      NumATensor describes the number of A tensors. The minimum number of tensors is 1(required).
///      NumBTensor describes the number of B tensors. The minimum number of tensors is 1(required).
template <index_t NumATensor = 1, index_t NumBTensor = 1>
struct UniversalMoeGemmHostArgs
{
    CK_TILE_HOST UniversalMoeGemmHostArgs(const std::array<const void*, NumATensor>& as_ptr_,
                                       const std::array<const void*, NumBTensor>& bs_ptr_,
                                       void* e_ptr_,
                                       index_t k_batch_,
                                       index_t M_,
                                       index_t N_,
                                       index_t K_,
                                       const std::array<index_t, NumATensor>& stride_As_,
                                       const std::array<index_t, NumBTensor>& stride_Bs_,
                                       index_t stride_E_)
        : as_ptr(as_ptr_),
          bs_ptr(bs_ptr_),
          e_ptr(e_ptr_),
          M(M_),
          N(N_),
          K(K_),
          stride_As(stride_As_),
          stride_Bs(stride_Bs_),
          stride_E(stride_E_)
    {
    }

    const std::array<const void*, NumATensor> as_ptr;
    const std::array<const void*, NumBTensor> bs_ptr;
    union
    {
        void* e_ptr;
        void* c_ptr;
    };
    index_t M;
    index_t N;
    index_t K;
    const std::array<index_t, NumATensor> stride_As;
    const std::array<index_t, NumBTensor> stride_Bs;
    union
    {
        index_t stride_E;
        index_t stride_C;
    };

    std::array<const void*, NumATensor> a_scale_ptr{};
    std::array<const void*, NumBTensor> b_scale_ptr{};
    std::array<index_t, NumATensor> stride_A_scales{};
    std::array<index_t, NumBTensor> stride_B_scales{};
    std::array<index_t, NumATensor> a_scale_k_block_lengths{};
    std::array<index_t, NumBTensor> b_scale_k_block_lengths{};
    std::array<index_t, NumBTensor> b_scale_n_block_lengths{};
};

/// @brief The GEMM kernel device arguments.
template <index_t NumATensor = 1, index_t NumBTensor = 1>
struct UniversalMoeGemmKernelArgs
{
    /// @brief The As input tensor's pointer to device memory.
    const std::array<const void*, NumATensor> as_ptr;
    /// @brief The Bs input tensor's pointer to device memory.
    const std::array<const void*, NumBTensor> bs_ptr;
    /// @brief The E output tensor's pointer to device memory.
    void* e_ptr;
    /// @brief GEMM's M dimension size.
    index_t M;
    /// @brief GEMM's N dimension size.
    index_t N;
    /// @brief GEMM's K dimension size.
    index_t K;
    /// @brief The distance between consecutive elements of non-contiguous dimension
    ///        (in memory) of As tensor.
    std::array<index_t, NumATensor> stride_As;
    /// @brief The distance between consecutive elements of non-contiguous dimension
    ///        (in memory) of Bs tensor.
    std::array<index_t, NumBTensor> stride_Bs;
    /// @brief The distance between consecutive elements of non-contiguous dimension
    ///        (in memory) of E tensor.
    index_t stride_E;

    std::array<const void*, NumATensor> a_scale_ptr{};
    std::array<const void*, NumBTensor> b_scale_ptr{};
    std::array<index_t, NumATensor> stride_A_scales{};
    std::array<index_t, NumBTensor> stride_B_scales{};
    std::array<index_t, NumATensor> a_scale_k_block_lengths{};
    std::array<index_t, NumBTensor> b_scale_k_block_lengths{};
    std::array<index_t, NumBTensor> b_scale_n_block_lengths{};
};

/// @brief The Universal GEMM kernel template.
///
/// @paragraph Overview Overview
///            This class provides the generic matrix multiplication kernel template. By semantic
///            division of GEMM algorithm into following parts we achieve flexible, versatile
///            and robust kernel implementation.
///
///            @li @b Prolog - The start of GEMM kernel implementation in @ref operator()
///                function call operator" which determines the work scope of each workgroup.
///            @li @b GemmPipeline - The core part @a "heart" of matrix multiplication algorithm.
///                This is the place where each workgroup is loading data from global memory and
///                carrying out dot products.
///            @li @b Epilogue - The @a "final" part of matrix multiplication implementation
///                 responsible for storing results to global memory. This is also the place where
///                 any additional operator fusion may take place.
///
///            Additionally both @ref GemmPipeline_ "GemmPipeline" and @ref EpiloguePipeline_
///            "EpiloguePipeline" are parameterized with so called @a Policy which determines all
///            internal details of those functional parts. You can think of it like both gemm and
///            epilogue pipelines provides the control-flow logic controlled by policies. Moreover
///            the policy is responsible for definition of all necessary data layouts and thread's
///            work distribution.
///
/// @tparam TilePartitioner_    The type of class providing mapping of workgroup index into the
///                             output data tile to be calculated. It determines the workgroup to
///                             data relationship (or in other words - which data would be
///                             processed and calculated by which workgroup).
/// @tparam GemmPipeline_       The type of class which provides the core part of matrix
///                             multiplication. This class should provide implementation of data
///                             loading from global memory and performing block-wise matrix
///                             multiplication. You can think of it as a work done by single
///                             workgroup point of view.
/// @tparam EpiloguePipeline_   The type of class providing the final part of matrix
///                             multiplication implementation. It is responsible for storing
///                             results calculated by @ref GemmPipeline_ "GemmPipeline" to
///                             the output E tensor in global memory.
template <typename TilePartitioner_, typename GemmPipeline_, typename EpiloguePipeline_>
struct UniversalMoeGemmKernel
{
    using TilePartitioner  = remove_cvref_t<TilePartitioner_>;
    using GemmPipeline     = remove_cvref_t<GemmPipeline_>;
    using EpiloguePipeline = remove_cvref_t<EpiloguePipeline_>;

    static constexpr bool ADataTypeIsTuple =
        is_detected<is_tuple, typename GemmPipeline::ADataType>::value;
    static constexpr bool BDataTypeIsTuple =
        is_detected<is_tuple, typename GemmPipeline::BDataType>::value;
    static constexpr bool ALayoutIsTuple =
        is_detected<is_tuple, typename GemmPipeline::ALayout>::value;
    static constexpr bool BLayoutIsTuple =
        is_detected<is_tuple, typename GemmPipeline::BLayout>::value;
    

    using AsLayout = std::conditional_t<ALayoutIsTuple,
                                        remove_cvref_t<typename GemmPipeline::ALayout>,
                                        remove_cvref_t<tuple<typename GemmPipeline::ALayout>>>;
    using BsLayout = std::conditional_t<BLayoutIsTuple,
                                        remove_cvref_t<typename GemmPipeline::BLayout>,
                                        remove_cvref_t<tuple<typename GemmPipeline::BLayout>>>;
    using AsDataType = std::conditional_t<ADataTypeIsTuple,
                                          remove_cvref_t<typename GemmPipeline::ADataType>,
                                          remove_cvref_t<tuple<typename GemmPipeline::ADataType>>>;
    using BsDataType = std::conditional_t<BDataTypeIsTuple,
                                          remove_cvref_t<typename GemmPipeline::BDataType>,
                                          remove_cvref_t<tuple<typename GemmPipeline::BDataType>>>;


    using ELayout   = remove_cvref_t<typename GemmPipeline::CLayout>;
    using EDataType = remove_cvref_t<typename EpiloguePipeline::ODataType>;

    static constexpr index_t kBlockSize = GemmPipeline::BlockSize;
    static constexpr index_t KLanePerBlock = TilePartitioner::KLanePerBlock;

    // Get the persistent kernel if the pipeline has it available
    struct has_persistent_kernel
    {
        template <typename T>
        using has_persistent_type = decltype(T::UsePersistentKernel);

        static constexpr bool value = []() {
            if constexpr(is_detected<has_persistent_type, GemmPipeline>{})
                return GemmPipeline::UsePersistentKernel;
            else
                return false;
        }();
    };
    static constexpr bool PersistentKernel = has_persistent_kernel::value;

    // Check if TilePartitioner has GetOutputOffset method with kargs and k_id
    struct has_tile_partitioner_output_offset_impl
    {
        template <typename T, typename KernelArgs>
        using has_get_output_offset_t =
            decltype(T::GetOutputOffset(std::declval<KernelArgs>(), std::declval<index_t>()));

        static constexpr bool value = []() {
            if constexpr(is_detected<has_get_output_offset_t, TilePartitioner>{})
                return true;
            else
                return false;
        }();
    };
    static constexpr bool has_tile_partitioner_output_offset =
        has_tile_partitioner_output_offset_impl::value;

    static constexpr auto I0 = number<0>();
    static constexpr auto I1 = number<1>();
    static constexpr auto I2 = number<2>();
    static constexpr auto I3 = number<3>{};
    static constexpr auto I4 = number<4>{};
    static constexpr auto I5 = number<5>{};

    static constexpr index_t NumATensor = AsDataType::size();
    static constexpr index_t NumBTensor = BsDataType::size();

    using ADataType = remove_cvref_t<std::tuple_element_t<I0, AsDataType>>;
    using BDataType = remove_cvref_t<std::tuple_element_t<I0, BsDataType>>;

    static_assert(AsLayout::size() == AsDataType::size(),
                  "The size of AsLayout and AsDataType should be the same");

    static_assert(BsLayout::size() == BsDataType::size(),
                  "The size of BsLayout and BsDataType should be the same");


    template <typename Pipeline, typename = void>
    struct get_a_scale_type
    {
        using type = ck_tile::null_type;
    };

    template <typename Pipeline>
    struct get_a_scale_type<Pipeline, std::void_t<typename Pipeline::AScaleDataType>>
    {
        using type = remove_cvref_t<typename Pipeline::AScaleDataType>;
    };

    template <typename Pipeline, typename = void>
    struct get_b_scale_type
    {
        using type = ck_tile::null_type;
    };

    template <typename Pipeline>
    struct get_b_scale_type<Pipeline, std::void_t<typename Pipeline::BScaleDataType>>
    {
        using type = remove_cvref_t<typename Pipeline::BScaleDataType>;
    };

    using KernelArgs =
        UniversalMoeGemmKernelArgs<AsLayout::size(), BsLayout::size()>;  // <1, 1>

    using AScaleDataType = typename get_a_scale_type<GemmPipeline>::type;
    using BScaleDataType = typename get_b_scale_type<GemmPipeline>::type;

    static_assert(!GemmPipeline::UseABScale ||
                      (!std::is_same_v<AScaleDataType, ck_tile::null_type> &&
                       !std::is_same_v<BScaleDataType, ck_tile::null_type>),
                  "UseABScale requires valid scale data types");

    [[nodiscard]] CK_TILE_HOST static const std::string GetName()
    {
        // clang-format off
        return concat('_', "gemm", gemm_prec_str<ADataType, BDataType>(), GemmPipeline::GetName());
        // clang-format on
    }

    CK_TILE_HOST static constexpr auto GridSize(index_t M, index_t N, index_t KBatch)
    {
        return dim3(TilePartitioner::GridSize(M, N), 1, KBatch);
    }

    /**
     * @brief Get the maximum occupancy grid size for the persistent kernel on the current device.
     * @return The maximum occupancy grid size.
     * @note This function queries the maximum occupancy of the kernel using
     *       `hipOccupancyMaxActiveBlocksPerMultiprocessor`.
     */
    CK_TILE_HOST static auto MaxOccupancyGridSize(const stream_config& s) -> dim3
    {
        using Kernel      = UniversalMoeGemmKernel<TilePartitioner, GemmPipeline, EpiloguePipeline>;
        const auto kernel = kentry<1, Kernel, KernelArgs>;
        int occupancy;
        hip_check_error(
            hipOccupancyMaxActiveBlocksPerMultiprocessor(&occupancy, kernel, BlockSize().x, 0));

        const int grid_size = get_available_compute_units(s) * occupancy;
        return dim3(grid_size, 1, 1);
    }

    CK_TILE_HOST static auto BlockSize()
    {
        if(ck_tile::is_wave32())
        {
            return dim3(kBlockSize / 2);
        }
        else
        {
            return dim3(kBlockSize);
        }
    }

    CK_TILE_HOST static constexpr KernelArgs
    MakeKernelArgs(const UniversalMoeGemmHostArgs<NumATensor, NumBTensor>& hostArgs)
    {
        return KernelArgs{hostArgs.as_ptr,
                          hostArgs.bs_ptr,
                          hostArgs.e_ptr,
                          hostArgs.M,
                          hostArgs.N,
                          hostArgs.K,
                          hostArgs.stride_As,
                          hostArgs.stride_Bs,
                          hostArgs.stride_E,
                          hostArgs.a_scale_ptr,
                          hostArgs.b_scale_ptr,
                          hostArgs.stride_A_scales,
                          hostArgs.stride_B_scales,
                          hostArgs.a_scale_k_block_lengths,
                          hostArgs.b_scale_k_block_lengths,
                          hostArgs.b_scale_n_block_lengths};
    }

    CK_TILE_HOST_DEVICE static constexpr index_t GetSmemSize()
    {
        return max(GemmPipeline::GetSmemSize(), EpiloguePipeline::GetSmemSize());
    }

    // struct SplitKBatchOffset
    // {
    //     __device__ SplitKBatchOffset(const KernelArgs& kargs, const std::size_t k_id = blockIdx.z)
    //     {
    //         constexpr auto K1   = TilePartitioner::BlockGemmShape::WarpTile::at(number<2>{});
    //         const index_t KRead = __builtin_amdgcn_readfirstlane((kargs.K + K1 - 1) / K1 * K1);

    //         static_for<0, NumATensor, 1>{}([&](auto index) {
    //             using AiLayout = remove_cvref_t<std::tuple_element_t<index.value, AsLayout>>;
    //             if constexpr(std::is_same_v<tensor_layout::gemm::RowMajor, AiLayout>)
    //             {
    //                 as_k_split_offset[index] = __builtin_amdgcn_readfirstlane(k_id * KRead);
    //             }
    //             else if constexpr(std::is_same_v<tensor_layout::gemm::ColumnMajor, AiLayout>)
    //             {
    //                 as_k_split_offset[index] =
    //                     __builtin_amdgcn_readfirstlane(k_id * KRead * kargs.stride_As[index]);
    //             }
    //         });

    //         static_for<0, NumBTensor, 1>{}([&](auto index) {
    //             using BiLayout = remove_cvref_t<std::tuple_element_t<index.value, BsLayout>>;
    //             if constexpr(std::is_same_v<tensor_layout::gemm::RowMajor, BiLayout>)
    //             {
    //                 bs_k_split_offset[index] =
    //                     __builtin_amdgcn_readfirstlane(k_id * KRead * kargs.stride_Bs[index]);
    //             }
    //             else if constexpr(std::is_same_v<tensor_layout::gemm::ColumnMajor, BiLayout>)
    //             {
    //                 bs_k_split_offset[index] = __builtin_amdgcn_readfirstlane(k_id * KRead);
    //             }
    //         });

    //         if constexpr(GemmPipeline::UseABScale)
    //         {
    //             static_for<0, NumATensor, 1>{}([&](auto index) {
    //                 using AiLayout = remove_cvref_t<std::tuple_element_t<index.value, AsLayout>>;
    //                 // A输入K方向量化尺度 (128)
    //                 const index_t block_len = kargs.a_scale_k_block_lengths[index] > 0
    //                                               ? kargs.a_scale_k_block_lengths[index]
    //                                               : static_cast<index_t>(1);
    //                 // K方向包含几次block read
    //                 const index_t coarse_kread = __builtin_amdgcn_readfirstlane(
    //                     ck_tile::integer_divide_ceil(KRead, block_len));
    //                 if constexpr(std::is_same_v<tensor_layout::gemm::RowMajor, AiLayout>)
    //                 {
    //                     as_scale_k_split_offset[index] =
    //                         __builtin_amdgcn_readfirstlane(k_id * coarse_kread);
    //                 }
    //                 else if constexpr(std::is_same_v<tensor_layout::gemm::ColumnMajor, AiLayout>)
    //                 {
    //                     as_scale_k_split_offset[index] = __builtin_amdgcn_readfirstlane(
    //                         k_id * coarse_kread * kargs.stride_A_scales[index]);
    //                 }
    //             });

    //             static_for<0, NumBTensor, 1>{}([&](auto index) {
    //                 using BiLayout = remove_cvref_t<std::tuple_element_t<index.value, BsLayout>>;
    //                 const index_t block_len = kargs.b_scale_k_block_lengths[index] > 0
    //                                               ? kargs.b_scale_k_block_lengths[index]
    //                                               : static_cast<index_t>(1);
    //                 const index_t coarse_kread = __builtin_amdgcn_readfirstlane(
    //                     ck_tile::integer_divide_ceil(KRead, block_len));
    //                 if constexpr(std::is_same_v<tensor_layout::gemm::RowMajor, BiLayout>)
    //                 {
    //                     bs_scale_k_split_offset[index] = __builtin_amdgcn_readfirstlane(
    //                         k_id * coarse_kread * kargs.stride_B_scales[index]);
    //                 }
    //                 else if constexpr(std::is_same_v<tensor_layout::gemm::ColumnMajor, BiLayout>)
    //                 {
    //                     bs_scale_k_split_offset[index] =
    //                         __builtin_amdgcn_readfirstlane(k_id * coarse_kread);
    //                 }
    //             });
    //         }

    //         if(k_id < 0)
    //         {
    //             splitted_k = __builtin_amdgcn_readfirstlane(KRead);
    //         }
    //         else
    //         {
    //             splitted_k = __builtin_amdgcn_readfirstlane(kargs.K);
    //         }
    //     }

    //     std::array<index_t, NumATensor> as_k_split_offset;
    //     std::array<index_t, NumBTensor> bs_k_split_offset;
    //     std::array<index_t, NumATensor> as_scale_k_split_offset{};
    //     std::array<index_t, NumBTensor> bs_scale_k_split_offset{};
    //     index_t splitted_k;
    // };

    CK_TILE_HOST static bool IsSupportedArgument(const KernelArgs& kargs)
    {
        const auto vectorSizeA = is_wave32() ? GemmPipeline::template GetVectorSizeA<true>()
                                             : GemmPipeline::template GetVectorSizeA<false>();
        bool AsTesnorIsValid   = {true};
        static_for<0, NumATensor, 1>{}([&](auto index) {
            using AiLayout = remove_cvref_t<std::tuple_element_t<index.value, AsLayout>>;
            if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
            {
                if(kargs.K % TilePartitioner::KPerBlock != 0 && GemmPipeline::kPadK == false)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR(
                            "Can't support K that is not a multiple of KPerBlock "
                            "without padding!");
                    }
                    AsTesnorIsValid = false;
                }
                if(kargs.K % vectorSizeA != 0)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR("K is not a multiple of vector load size for A tensor!");
                    }
                    AsTesnorIsValid = false;
                }
            }
            else
            {
                if(kargs.M % TilePartitioner::MPerBlock != 0 && GemmPipeline::kPadM == false)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR(
                            "Can't support M that is not a multiple of MPerBlock without padding!");
                    }
                    AsTesnorIsValid = false;
                }
                if(kargs.M % vectorSizeA != 0)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR("M is not a multiple of vector load size for A tensor!");
                    }
                    AsTesnorIsValid = false;
                }
            }
        });

        bool BsTesnorIsValid   = {true};
        const auto vectorSizeB = is_wave32() ? GemmPipeline::template GetVectorSizeB<true>()
                                             : GemmPipeline::template GetVectorSizeB<false>();
        static_for<0, NumBTensor, 1>{}([&](auto index) {
            using BiLayout = remove_cvref_t<std::tuple_element_t<index.value, BsLayout>>;
            if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::RowMajor>)
            {
                if(kargs.N % TilePartitioner::NPerBlock != 0 && GemmPipeline::kPadN == false)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR(
                            "Can't support N that is not a multiple of NPerBlock without padding!");
                    }
                    BsTesnorIsValid = false;
                }
                if(kargs.N % vectorSizeB != 0)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR("N is not a multiple of vector load size for B tensor!");
                    }
                    BsTesnorIsValid = false;
                }
            }
            else
            {
                if(kargs.K % TilePartitioner::KPerBlock != 0 && GemmPipeline::kPadK == false)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR(
                            "Can't support K that is not a multiple of KPerBlock "
                            "without padding!");
                    }
                    BsTesnorIsValid = false;
                }
                if(kargs.K % vectorSizeB != 0)
                {
                    if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                    {
                        CK_TILE_ERROR("K is not a multiple of vector load size for B tensor!");
                    }
                    BsTesnorIsValid = false;
                }
            }
        });

        if constexpr(std::is_same_v<ELayout, tensor_layout::gemm::RowMajor>)
        {
            if(kargs.N % TilePartitioner::NPerBlock != 0 && GemmPipeline::kPadN == false)
            {
                if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                {
                    CK_TILE_ERROR(
                        "Can't support N that is not a multiple of NPerBlock without padding!");
                }
                return false;
            }
            if(kargs.N % EpiloguePipeline::GetVectorSizeC() != 0)
            {
                if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                {
                    CK_TILE_ERROR("N is not a multiple of vector load size for C tensor!");
                }
                return false;
            }
        }
        else
        {
            if(kargs.M % TilePartitioner::MPerBlock != 0 && GemmPipeline::kPadM == false)
            {
                if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                {
                    CK_TILE_ERROR(
                        "Can't support M that is not a multiple of MPerBlock without padding!");
                }
                return false;
            }
            if(kargs.M % EpiloguePipeline::GetVectorSizeC() != 0)
            {
                if(ck_tile::EnvIsEnabled(CK_TILE_ENV(CK_TILE_LOGGING)))
                {
                    CK_TILE_ERROR("M is not a multiple of vector load size for C tensor!");
                }
                return false;
            }
        }
        return AsTesnorIsValid && BsTesnorIsValid;
    }

    
    template <memory_operation_enum DstInMemOp = memory_operation_enum::set>
    CK_TILE_DEVICE static auto
    MakeMoeGemm1TensorViews(const std::array<const ADataType*, NumATensor>& as_ptr,
                            const std::array<const BDataType*, NumBTensor>& bs_ptr,
                            EDataType* e_ptr,
                            const KernelArgs& kargs,
                            const index_t moe_num_tokens,
                            const std::array<const AScaleDataType*, NumATensor>& as_scale_ptr
                                [[maybe_unused]],
                            const std::array<const BScaleDataType*, NumBTensor>& bs_scale_ptr
                                [[maybe_unused]])
    {
        static_assert(!TilePartitioner::BlockGemmShape::PermuteA, "Not implemented!");

        const auto& as_tensor_view = generate_tuple(
            [&](auto i) {
                using AiLayout   = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                using AiDataType = remove_cvref_t<std::tuple_element_t<i.value, AsDataType>>;
                if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                {
                    return make_naive_tensor_view<address_space_enum::global>(
                        static_cast<const AiDataType*>(as_ptr[i]),
                        make_tuple(moe_num_tokens, kargs.K),
                        make_tuple(kargs.stride_As[i], 1),
                        number<GemmPipeline::GetVectorSizeA()>{},
                        number<1>{});
                }
                else
                {
                    return make_naive_tensor_view<address_space_enum::global>(
                        static_cast<const AiDataType*>(as_ptr[i]),
                        make_tuple(kargs.K, moe_num_tokens),
                        make_tuple(kargs.stride_As[i], 1),
                        number<GemmPipeline::GetVectorSizeA()>{},
                        number<1>{});
                }
            },
            number<NumATensor>{});

        const auto& bs_tensor_view = generate_tuple(
            [&](auto i) {
                using BiLayout   = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                using BiDataType = remove_cvref_t<std::tuple_element_t<i.value, BsDataType>>;
                if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::RowMajor>)
                {
                    if constexpr(TilePartitioner::BlockGemmShape::PermuteB)
                    {
                        constexpr index_t K1 = GemmPipeline::GetSmemPackB();
                        const index_t K0     = kargs.K / K1;
                        constexpr index_t VectorSizeB =
                            std::min(K1, GemmPipeline::GetVectorSizeB());
                        const auto b_k0_n_k1_desc =
                            make_naive_tensor_descriptor(make_tuple(K0, kargs.N, K1),
                                                         make_tuple(kargs.N * K1, K1, I1),
                                                         number<VectorSizeB>{},
                                                         number<1>{});
                        const auto b_n_k_desc = transform_tensor_descriptor(
                            b_k0_n_k1_desc,
                            make_tuple(make_merge_transform(make_tuple(K0, K1)),
                                       make_pass_through_transform(kargs.N)),
                            make_tuple(sequence<0, 2>{}, sequence<1>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                        return make_tensor_view<address_space_enum::global>(
                            static_cast<const BiDataType*>(bs_ptr[i]), b_n_k_desc);
                    }
                    else
                    {
                        return make_naive_tensor_view<address_space_enum::global>(
                            bs_ptr[i],
                            make_tuple(kargs.K, kargs.N),
                            make_tuple(kargs.stride_Bs[i], 1),
                            number<GemmPipeline::GetVectorSizeB()>{},
                            number<1>{});
                    }
                }
                else
                {
                    if constexpr(TilePartitioner::BlockGemmShape::PermuteB)
                    {
                        constexpr index_t K1 = GemmPipeline::GetSmemPackB();
                        const index_t K0     = kargs.K / K1;
                        constexpr index_t VectorSizeB =
                            std::min(K1, GemmPipeline::GetVectorSizeB());
                        const auto b_k0_n_k1_desc =
                            make_naive_tensor_descriptor(make_tuple(K0, kargs.N, K1),
                                                         make_tuple(kargs.N * K1, K1, I1),
                                                         number<VectorSizeB>{},
                                                         number<1>{});
                        const auto b_n_k_desc = transform_tensor_descriptor(
                            b_k0_n_k1_desc,
                            make_tuple(make_merge_transform(make_tuple(K0, K1)),
                                       make_pass_through_transform(kargs.N)),
                            make_tuple(sequence<0, 2>{}, sequence<1>{}),
                            make_tuple(sequence<1>{}, sequence<0>{}));
                        return make_tensor_view<address_space_enum::global>(
                            static_cast<const BiDataType*>(bs_ptr[i]), b_n_k_desc);
                    }
                    else
                    {
                        if constexpr(GemmPipeline::Preshuffle)
                        {
                            index_t kFlatK =
                                GemmPipeline::BlockGemmShape::flatKPerWarp *
                                (kargs.K / TilePartitioner::BlockGemmShape::WarpTile::at(number<2>{}));
                            index_t kFlatN = kargs.N * kargs.K / kFlatK;

                            return make_naive_tensor_view<address_space_enum::global>(
                                bs_ptr[i],
                                make_tuple(kFlatN, kFlatK),
                                make_tuple(kFlatK, 1),
                                number<GemmPipeline::GetVectorSizeB()>{},
                                number<1>{});
                        }
                        else
                        {
                            return make_naive_tensor_view<address_space_enum::global>(
                                bs_ptr[i],
                                make_tuple(kargs.N, kargs.K),
                                make_tuple(kargs.stride_Bs[i], 1),
                                number<GemmPipeline::GetVectorSizeB()>{},
                                number<1>{});
                        }
                    }
                }
            },
            number<NumBTensor>{});

        // TODO: enable vector write for C in ColMajor
        const auto& e_tensor_view = [&]() {
            if constexpr(std::is_same_v<ELayout, tensor_layout::gemm::RowMajor>)
            {
                return make_naive_tensor_view<address_space_enum::global, DstInMemOp>(
                    e_ptr,
                    make_tuple(kargs.M, kargs.N), // arguments not matching with flatmm.
                    make_tuple(kargs.stride_E, 1),
                    number<EpiloguePipeline::GetVectorSizeC()>{},
                    number<1>{});
            }
            else
            {
                return make_naive_tensor_view<address_space_enum::global, DstInMemOp>(
                    e_ptr,
                    make_tuple(kargs.M, kargs.N),
                    make_tuple(1, kargs.stride_E),
                    number<1>{},
                    number<1>{});
            }
        }();

        if constexpr(GemmPipeline::UseABScale)
        {
            const auto& a_scale_tensor_view = generate_tuple(
                [&](auto i) {
                    using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                    const index_t block_len = kargs.a_scale_k_block_lengths[i];
                    const index_t coarse_k_len = ck_tile::integer_divide_ceil(kargs.K, block_len);

                    if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(moe_num_tokens, coarse_k_len, KLanePerBlock),
                            make_tuple(kargs.stride_A_scales[i], 1, 0),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            as_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_pass_through_transform(moe_num_tokens),
                                       make_merge_transform(make_tuple(coarse_k_len, KLanePerBlock))),
                            make_tuple(sequence<0>{}, sequence<1, 2>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                    else
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(coarse_k_len, KLanePerBlock, moe_num_tokens),
                            make_tuple(1, 0, kargs.stride_A_scales[i]),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            as_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_merge_transform(
                                           make_tuple(coarse_k_len, KLanePerBlock)),
                                       make_pass_through_transform(moe_num_tokens)),
                            make_tuple(sequence<0, 1>{}, sequence<2>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                },
                number<NumATensor>{});

            const auto& b_scale_tensor_view = generate_tuple(
                [&](auto i) {
                    using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                    const index_t block_k = kargs.b_scale_k_block_lengths[i];
                    const index_t block_n = kargs.b_scale_n_block_lengths[i] > 0
                                                ? kargs.b_scale_n_block_lengths[i]
                                                : static_cast<index_t>(1);
                    const index_t coarse_k_len = ck_tile::integer_divide_ceil(
                        kargs.K, block_k);
                    const index_t coarse_n_len = ck_tile::integer_divide_ceil(kargs.N, block_n);


                    if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(coarse_k_len, KLanePerBlock, coarse_n_len, block_n),  //按照NPerBlock扩展，而不是量化的粒度，因move window需要
                            make_tuple(1, 0, kargs.stride_B_scales[i], 0),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            bs_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_merge_transform(
                                           make_tuple(coarse_k_len, KLanePerBlock)),
                                       make_merge_transform(
                                           make_tuple(coarse_n_len, block_n))),
                            make_tuple(sequence<0, 1>{}, sequence<2, 3>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                    else
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(coarse_n_len, block_n, coarse_k_len, KLanePerBlock),
                            make_tuple(kargs.stride_B_scales[i], 0, 1, 0),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            bs_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_merge_transform(make_tuple(coarse_n_len, block_n)),
                                       make_merge_transform(make_tuple(coarse_k_len, KLanePerBlock))),
                            make_tuple(sequence<0, 1>{}, sequence<2, 3>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                },
                number<NumBTensor>{});

            return make_tuple(as_tensor_view,
                              bs_tensor_view,
                              e_tensor_view,
                              a_scale_tensor_view,
                              b_scale_tensor_view);
        }
        else
        {
            return make_tuple(as_tensor_view, bs_tensor_view, e_tensor_view);
        }
    }

    template <memory_operation_enum DstInMemOp = memory_operation_enum::set>
    CK_TILE_DEVICE static auto
    MakeMoeGemm2TensorViews(const std::array<const ADataType*, NumATensor>& as_ptr,
                            const std::array<const BDataType*, NumBTensor>& bs_ptr,
                            EDataType* e_ptr,
                            const KernelArgs& kargs,
                            const index_t moe_num_tokens,
                            const std::array<const AScaleDataType*, NumATensor>& as_scale_ptr
                                [[maybe_unused]],
                            const std::array<const BScaleDataType*, NumBTensor>& bs_scale_ptr
                                [[maybe_unused]])
    {
        static_assert(!TilePartitioner::BlockGemmShape::PermuteA, "Not implemented!");

        const auto& as_tensor_view = generate_tuple(
            [&](auto i) {
                using AiLayout   = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                using AiDataType = remove_cvref_t<std::tuple_element_t<i.value, AsDataType>>;
                if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                {
                    return make_naive_tensor_view<address_space_enum::global>(
                        static_cast<const AiDataType*>(as_ptr[i]),
                        make_tuple(kargs.M, kargs.K),
                        make_tuple(kargs.stride_As[i], 1),
                        number<GemmPipeline::GetVectorSizeA()>{},
                        number<1>{});
                }
                else
                {
                    return make_naive_tensor_view<address_space_enum::global>(
                        static_cast<const AiDataType*>(as_ptr[i]),
                        make_tuple(kargs.K, kargs.M),
                        make_tuple(kargs.stride_As[i], 1),
                        number<GemmPipeline::GetVectorSizeA()>{},
                        number<1>{});
                }
            },
            number<NumATensor>{});

        const auto& bs_tensor_view = generate_tuple(
            [&](auto i) {
                using BiLayout   = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                using BiDataType = remove_cvref_t<std::tuple_element_t<i.value, BsDataType>>;
                if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::RowMajor>)
                {
                    if constexpr(TilePartitioner::BlockGemmShape::PermuteB)
                    {
                        constexpr index_t K1 = GemmPipeline::GetSmemPackB();
                        const index_t K0     = kargs.K / K1;
                        constexpr index_t VectorSizeB =
                            std::min(K1, GemmPipeline::GetVectorSizeB());
                        const auto b_k0_n_k1_desc =
                            make_naive_tensor_descriptor(make_tuple(K0, kargs.N, K1),
                                                         make_tuple(kargs.N * K1, K1, I1),
                                                         number<VectorSizeB>{},
                                                         number<1>{});
                        const auto b_n_k_desc = transform_tensor_descriptor(
                            b_k0_n_k1_desc,
                            make_tuple(make_merge_transform(make_tuple(K0, K1)),
                                       make_pass_through_transform(kargs.N)),
                            make_tuple(sequence<0, 2>{}, sequence<1>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                        return make_tensor_view<address_space_enum::global>(
                            static_cast<const BiDataType*>(bs_ptr[i]), b_n_k_desc);
                    }
                    else
                    {
                        return make_naive_tensor_view<address_space_enum::global>(
                            bs_ptr[i],
                            make_tuple(kargs.K, kargs.N),
                            make_tuple(kargs.stride_Bs[i], 1),
                            number<GemmPipeline::GetVectorSizeB()>{},
                            number<1>{});
                    }
                }
                else
                {
                    if constexpr(TilePartitioner::BlockGemmShape::PermuteB)
                    {
                        constexpr index_t K1 = GemmPipeline::GetSmemPackB();
                        const index_t K0     = kargs.K / K1;
                        constexpr index_t VectorSizeB =
                            std::min(K1, GemmPipeline::GetVectorSizeB());
                        const auto b_k0_n_k1_desc =
                            make_naive_tensor_descriptor(make_tuple(K0, kargs.N, K1),
                                                         make_tuple(kargs.N * K1, K1, I1),
                                                         number<VectorSizeB>{},
                                                         number<1>{});
                        const auto b_n_k_desc = transform_tensor_descriptor(
                            b_k0_n_k1_desc,
                            make_tuple(make_merge_transform(make_tuple(K0, K1)),
                                       make_pass_through_transform(kargs.N)),
                            make_tuple(sequence<0, 2>{}, sequence<1>{}),
                            make_tuple(sequence<1>{}, sequence<0>{}));
                        return make_tensor_view<address_space_enum::global>(
                            static_cast<const BiDataType*>(bs_ptr[i]), b_n_k_desc);
                    }
                    else
                    {
                        if constexpr(GemmPipeline::Preshuffle)
                        {
                            index_t kFlatK =
                                GemmPipeline::BlockGemmShape::flatKPerWarp *
                                (kargs.K / TilePartitioner::BlockGemmShape::WarpTile::at(number<2>{}));
                            index_t kFlatN = kargs.N * kargs.K / kFlatK;

                            return make_naive_tensor_view<address_space_enum::global>(
                                bs_ptr[i],
                                make_tuple(kFlatN, kFlatK),
                                make_tuple(kFlatK, 1),
                                number<GemmPipeline::GetVectorSizeB()>{},
                                number<1>{});
                        }
                        else
                        {
                            return make_naive_tensor_view<address_space_enum::global>(
                                bs_ptr[i],
                                make_tuple(kargs.N, kargs.K),
                                make_tuple(kargs.stride_Bs[i], 1),
                                number<GemmPipeline::GetVectorSizeB()>{},
                                number<1>{});
                        }
                    }
                }
            },
            number<NumBTensor>{});

        // TODO: enable vector write for C in ColMajor
        const auto& e_tensor_view = [&]() {
            if constexpr(std::is_same_v<ELayout, tensor_layout::gemm::RowMajor>)
            {
                return make_naive_tensor_view<address_space_enum::global, DstInMemOp>(
                    e_ptr,
                    make_tuple(moe_num_tokens, kargs.N), // arguments not matching with flatmm.
                    make_tuple(kargs.stride_E, 1),
                    number<EpiloguePipeline::GetVectorSizeC()>{},
                    number<1>{});
            }
            else
            {
                return make_naive_tensor_view<address_space_enum::global, DstInMemOp>(
                    e_ptr,
                    make_tuple(moe_num_tokens, kargs.N),
                    make_tuple(1, kargs.stride_E),
                    number<1>{},
                    number<1>{});
            }
        }();

        if constexpr(GemmPipeline::UseABScale)
        {
            const auto& a_scale_tensor_view = generate_tuple(
                [&](auto i) {
                    using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                    const index_t block_len = kargs.a_scale_k_block_lengths[i];
                    const index_t coarse_k_len = ck_tile::integer_divide_ceil(
                        kargs.K, block_len);
                    if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(kargs.M, coarse_k_len, KLanePerBlock),
                            make_tuple(kargs.stride_A_scales[i], 1, 0),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            as_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_pass_through_transform(kargs.M),
                                       make_merge_transform(
                                           make_tuple(coarse_k_len, KLanePerBlock))),
                            make_tuple(sequence<0>{}, sequence<1, 2>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                    else
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(coarse_k_len, KLanePerBlock, kargs.M),
                            make_tuple(1, 0, kargs.stride_A_scales[i]),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            as_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_merge_transform(
                                           make_tuple(coarse_k_len, KLanePerBlock)),
                                       make_pass_through_transform(kargs.M)),
                            make_tuple(sequence<0, 1>{}, sequence<2>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                },
                number<NumATensor>{});

            const auto& b_scale_tensor_view = generate_tuple(
                [&](auto i) {
                    using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                    const index_t block_k = kargs.b_scale_k_block_lengths[i];
                    const index_t block_n = kargs.b_scale_n_block_lengths[i] > 0
                                                ? kargs.b_scale_n_block_lengths[i]
                                                : static_cast<index_t>(1);
                    const index_t coarse_k_len = ck_tile::integer_divide_ceil(kargs.K, block_k);
                    const index_t coarse_n_len = ck_tile::integer_divide_ceil(kargs.N, block_n);
                    
                    if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(coarse_k_len, KLanePerBlock, coarse_n_len, block_n),
                            make_tuple(1, 0, kargs.stride_B_scales[i], 0),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            bs_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_merge_transform(
                                           make_tuple(coarse_k_len, KLanePerBlock)),
                                       make_merge_transform(
                                           make_tuple(coarse_n_len, block_n))),
                            make_tuple(sequence<0, 1>{}, sequence<2, 3>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                    else
                    {
                        const auto desc = make_naive_tensor_descriptor(
                            make_tuple(coarse_n_len, block_n, coarse_k_len, KLanePerBlock),
                            make_tuple(kargs.stride_B_scales[i], 0, 1, 0),
                            number<1>{},
                            number<1>{});
                        auto base_view = make_tensor_view<address_space_enum::global>(
                            bs_scale_ptr[i], desc);

                        return transform_tensor_view(
                            base_view,
                            make_tuple(make_merge_transform(make_tuple(coarse_n_len, block_n)),
                                       make_merge_transform(make_tuple(coarse_k_len, KLanePerBlock))),
                            make_tuple(sequence<0, 1>{}, sequence<2, 3>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));
                    }
                },
                number<NumBTensor>{});

            return make_tuple(as_tensor_view,
                              bs_tensor_view,
                              e_tensor_view,
                              a_scale_tensor_view,
                              b_scale_tensor_view);
        }
        else
        {
            return make_tuple(as_tensor_view, bs_tensor_view, e_tensor_view);
        }
    }


    template <typename TensorView>
    CK_TILE_DEVICE static auto MakeGemmPadViews(const TensorView& views)
    {
        const auto& as_pad_view = generate_tuple(
            [&](auto i) {
                const auto& a_tensor_view = views.at(I0);
                using AiLayout            = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                {
                    return pad_tensor_view(a_tensor_view[i],
                                           make_tuple(number<TilePartitioner::MPerBlock>{},
                                                      number<TilePartitioner::KPerBlock>{}),
                                           sequence<false, GemmPipeline::kPadK>{});
                }
                else
                {
                    return pad_tensor_view(a_tensor_view[i],
                                           make_tuple(number<TilePartitioner::KPerBlock>{},
                                                      number<TilePartitioner::MPerBlock>{}),
                                           sequence<false, GemmPipeline::kPadM>{});
                }
            },
            number<NumATensor>{});

        const auto& b_flat_pad_view = views.at(I1);

        const auto& bs_pad_view = generate_tuple(
            [&](auto i) {
                const auto& b_tensor_view = views.at(I1);
                using BiLayout            = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::ColumnMajor>)
                {
                    return pad_tensor_view(b_tensor_view[i],
                                           make_tuple(number<TilePartitioner::NPerBlock>{},
                                                      number<TilePartitioner::KPerBlock>{}),
                                           sequence<false, GemmPipeline::kPadK>{});
                }
                else
                {
                    return pad_tensor_view(b_tensor_view[i],
                                           make_tuple(number<TilePartitioner::KPerBlock>{},
                                                      number<TilePartitioner::NPerBlock>{}),
                                           sequence<false, GemmPipeline::kPadN>{});
                }
            },
            number<NumBTensor>{});

        // TODO vector write in for C in ColMajor
        const auto& e_pad_view = [&]() {
            const auto& e_tensor_view = views.at(I2);
            if constexpr(std::is_same_v<ELayout, tensor_layout::gemm::RowMajor>)
            {
                return pad_tensor_view(e_tensor_view,
                                       make_tuple(number<TilePartitioner::MPerBlock>{},
                                                  number<TilePartitioner::NPerBlock>{}),
                                       sequence<false, GemmPipeline::kPadN>{});
            }
            else
            {
                return pad_tensor_view(e_tensor_view,
                                       make_tuple(number<TilePartitioner::MPerBlock>{},
                                                  number<TilePartitioner::NPerBlock>{}),
                                       sequence<GemmPipeline::kPadM, false>{});
            }
        }();

        if constexpr(GemmPipeline::UseABScale)
        {
            const auto& a_scale_tensor_view = views.at(I3);
            const auto& b_scale_tensor_view = views.at(I4);

            const auto& a_scale_pad_view = generate_tuple(
                [&](auto i) {
                    using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                    if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        return pad_tensor_view(a_scale_tensor_view[i],
                                               make_tuple(number<TilePartitioner::MPerBlock>{},
                                                          number<KLanePerBlock>{}),
                                               sequence<false, false>{});
                    }
                    else
                    {
                        return pad_tensor_view(a_scale_tensor_view[i],
                                               make_tuple(number<KLanePerBlock>{},
                                                          number<TilePartitioner::MPerBlock>{}),
                                               sequence<false, false>{});
                    }
                },
                number<NumATensor>{});

            const auto& b_scale_pad_view = generate_tuple(
                [&](auto i) {
                    using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                    if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::ColumnMajor>)
                    {
                        return pad_tensor_view(b_scale_tensor_view[i],
                                               make_tuple(number<TilePartitioner::NPerBlock>{},
                                                          number<KLanePerBlock>{}),
                                               sequence<false, false>{});
                    }
                    else
                    {
                        return pad_tensor_view(b_scale_tensor_view[i],
                                               make_tuple(number<KLanePerBlock>{},
                                                          number<TilePartitioner::NPerBlock>{}),
                                               sequence<false, false>{});
                    }
                },
                number<NumBTensor>{});

            if constexpr(GemmPipeline::Preshuffle)
            {
                return make_tuple(as_pad_view,
                                  b_flat_pad_view,
                                  e_pad_view,
                                  a_scale_pad_view,
                                  b_scale_pad_view);
            }
            else
            {
                return make_tuple(as_pad_view,
                                  bs_pad_view,
                                  e_pad_view,
                                  a_scale_pad_view,
                                  b_scale_pad_view);
            }
        }
        else
        {
            if constexpr(GemmPipeline::Preshuffle)
            {
                // For flatmm, we need to use the flat B tensor view
                return make_tuple(as_pad_view, b_flat_pad_view, e_pad_view);
            }
            else
            {
                return make_tuple(as_pad_view, bs_pad_view, e_pad_view);
            }
        }
    }

    template <typename PadView>
    CK_TILE_DEVICE static auto
    MakeMoeGemm1TileWindows(const PadView& views, const index_t i_m, const index_t i_n, const index_t moe_token_id, const index_t a_scale_token_id)
    {
        const auto& as_pad_view = views.at(I0);
        const auto& bs_pad_view = views.at(I1);
        const auto& e_pad_view  = views.at(I2);

        const auto& as_block_window = generate_tuple(
            [&](auto i) {
                using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                {
                    const auto lengths = as_pad_view[i].get_tensor_descriptor().get_lengths();
                    const auto m_len   = lengths[number<0>{}];
                    const auto k_len   = lengths[number<1>{}];

                    const auto a_gather_view_ = transform_tensor_view(
                        as_pad_view[i],
                        make_tuple(make_indexing_transform(m_len, moe_token_id),
                                make_pass_through_transform(k_len)),
                        make_tuple(sequence<0>{}, sequence<1>{}),
                        make_tuple(sequence<0>{}, sequence<1>{}));

                    return make_tile_window(
                        a_gather_view_,
                        make_tuple(number<TilePartitioner::MPerBlock>{},
                                   number<TilePartitioner::KPerBlock>{}),
                        {0, 0});
                }
                else
                {
                    return make_tile_window(as_pad_view[i],
                                            make_tuple(number<TilePartitioner::KPerBlock>{},
                                                       number<TilePartitioner::MPerBlock>{}),
                                            {0, i_m});
                }
            },
            number<NumATensor>{});

        const auto& bs_block_window = generate_tuple(
            [&](auto i) {
                using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                if constexpr(GemmPipeline::Preshuffle)
                {
                    return make_tile_window(
                        bs_pad_view[i],
                        make_tuple(number<GemmPipeline::BlockGemmShape::flatNPerWarp>{},
                                   number<GemmPipeline::BlockGemmShape::flatKPerWarp>{}),
                        {static_cast<int>(i_n / GemmPipeline::BlockGemmShape::WarpTile::at(I1)),
                         0});
                }
                else
                {
                    if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::ColumnMajor>)
                    {
                        return make_tile_window(bs_pad_view[i],
                                                make_tuple(number<TilePartitioner::NPerBlock>{},
                                                           number<TilePartitioner::KPerBlock>{}),
                                                {i_n, 0});
                    }
                    else
                    {
                        return make_tile_window(bs_pad_view[i],
                                                make_tuple(number<TilePartitioner::KPerBlock>{},
                                                           number<TilePartitioner::NPerBlock>{}),
                                                {0, i_n});
                    }
                }
            },
            number<NumBTensor>{});

        auto e_block_window = make_tile_window(
            e_pad_view,
            make_tuple(number<TilePartitioner::MPerBlock>{}, number<TilePartitioner::NPerBlock>{}),
            {i_m, i_n});

        if constexpr(GemmPipeline::UseABScale)
        {
            const auto& a_scale_pad_view = views.at(I3);
            const auto& b_scale_pad_view = views.at(I4);

            const auto& a_scale_block_window = generate_tuple(
                [&](auto i) {
                    using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                    if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        const auto lengths = a_scale_pad_view[i].get_tensor_descriptor().get_lengths();
                        const index_t m_len   = lengths[number<0>{}];
                        const index_t k_len   = lengths[number<1>{}];

                        // if (blockIdx.x == 0 && blockIdx.y == 0 && blockIdx.z == 0 && threadIdx.x <= 3)
                        // {
                        //     // debug print
                        //     printf("a_scale_pad_view[%d][thread %d] lengths: %d, %d, a_scale_token_id = %d\n",
                        //         i.value, threadIdx.x, m_len, k_len, a_scale_token_id);
                        // }

                        const auto a_scale_gather_view = transform_tensor_view(
                            a_scale_pad_view[i],
                            make_tuple(make_indexing_transform(m_len, a_scale_token_id),
                                       make_pass_through_transform(k_len)),
                            make_tuple(sequence<0>{}, sequence<1>{}),
                            make_tuple(sequence<0>{}, sequence<1>{}));

                        return make_tile_window(
                            a_scale_gather_view,
                            make_tuple(number<TilePartitioner::MPerBlock>{},
                                       number<KLanePerBlock>{}),
                            {0, 0});
                    }
                    else
                    {
                        return make_tile_window(a_scale_pad_view[i],
                                                make_tuple(number<KLanePerBlock>{},
                                                           number<TilePartitioner::MPerBlock>{}),
                                                {0, i_m});
                    }
                },
                number<NumATensor>{});

            const auto& b_scale_block_window = generate_tuple(
                [&](auto i) {
                    using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                    if constexpr(GemmPipeline::Preshuffle)
                    {
                        return make_tile_window(
                            b_scale_pad_view[i],
                            make_tuple(number<GemmPipeline::BlockGemmShape::flatNPerWarp>{},
                                       number<GemmPipeline::BlockGemmShape::flatKPerWarp>{}),
                            {static_cast<int>(i_n /
                                              GemmPipeline::BlockGemmShape::WarpTile::at(I1)),
                             0});
                    }
                    else
                    {
                        if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::ColumnMajor>)
                        {
                            return make_tile_window(b_scale_pad_view[i],
                                                    make_tuple(number<TilePartitioner::NPerBlock>{},
                                                               number<KLanePerBlock>{}),
                                                    {i_n, 0});
                        }
                        else
                        {
                            return make_tile_window(b_scale_pad_view[i],
                                                    make_tuple(number<KLanePerBlock>{},
                                                               number<TilePartitioner::NPerBlock>{}),
                                                    {0, i_n});
                        }
                    }
                },
                number<NumBTensor>{});

            return make_tuple(as_block_window,
                              bs_block_window,
                              e_block_window,
                              a_scale_block_window,
                              b_scale_block_window);
        }
        else
        {
            return make_tuple(as_block_window, bs_block_window, e_block_window);
        }
    }

    template <typename PadView, typename IndexAdaptor>
    CK_TILE_DEVICE static auto MakeMoeGemm2TileWindows(const PadView& views,
                                                       const index_t i_m,
                                                       const index_t i_n,
                                                       const IndexAdaptor& index_adaptor)
    {
        const auto& as_pad_view = views.at(I0);
        const auto& bs_pad_view = views.at(I1);
        const auto& e_pad_view  = views.at(I2);

        const auto& as_block_window = generate_tuple(
            [&](auto i) {
                using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                {
                    return make_tile_window(as_pad_view[i],
                                            make_tuple(number<TilePartitioner::MPerBlock>{},
                                                       number<TilePartitioner::KPerBlock>{}),
                                            {i_m, 0});
                }
                else
                {
                    return make_tile_window(as_pad_view[i],
                                            make_tuple(number<TilePartitioner::KPerBlock>{},
                                                       number<TilePartitioner::MPerBlock>{}),
                                            {0, i_m});
                }
            },
            number<NumATensor>{});

        const auto& bs_block_window = generate_tuple(
            [&](auto i) {
                using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                if constexpr(GemmPipeline::Preshuffle)
                {
                    return make_tile_window(
                        bs_pad_view[i],
                        make_tuple(number<GemmPipeline::BlockGemmShape::flatNPerWarp>{},
                                   number<GemmPipeline::BlockGemmShape::flatKPerWarp>{}),
                        {static_cast<int>(i_n / GemmPipeline::BlockGemmShape::WarpTile::at(I1)),
                         0});
                }
                else
                {
                    if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::ColumnMajor>)
                    {
                        return make_tile_window(bs_pad_view[i],
                                                make_tuple(number<TilePartitioner::NPerBlock>{},
                                                           number<TilePartitioner::KPerBlock>{}),
                                                {i_n, 0});
                    }
                    else
                    {
                        return make_tile_window(bs_pad_view[i],
                                                make_tuple(number<TilePartitioner::KPerBlock>{},
                                                           number<TilePartitioner::NPerBlock>{}),
                                                {0, i_n});
                    }
                }
            },
            number<NumBTensor>{});
        
        const auto lengths = e_pad_view.get_tensor_descriptor().get_lengths();
        const auto m_len   = lengths[number<0>{}];
        const auto n_len   = lengths[number<1>{}];

        // if (blockIdx.x == 0 && blockIdx.y == 0 && blockIdx.z == 0) {
        //     printf("######### Thread[%d]   moe_token_id: %d\n", threadIdx.x, moe_token_id);
        // }


        const auto e_gather_view_ = transform_tensor_view(
            e_pad_view,
            make_tuple(make_indexing_transform_with_adaptor(m_len, index_adaptor),
                       make_pass_through_transform(n_len)),
            make_tuple(sequence<0>{}, sequence<1>{}),
            make_tuple(sequence<0>{}, sequence<1>{}));

        auto e_block_window = make_tile_window(e_gather_view_,
                                               make_tuple(number<TilePartitioner::MPerBlock>{},
                                                          number<TilePartitioner::NPerBlock>{}),
                                               {0, i_n});

        if constexpr(GemmPipeline::UseABScale)
        {
            const auto& a_scale_pad_view = views.at(I3);
            const auto& b_scale_pad_view = views.at(I4);

            const auto& a_scale_block_window = generate_tuple(
                [&](auto i) {
                    using AiLayout = remove_cvref_t<std::tuple_element_t<i.value, AsLayout>>;
                    if constexpr(std::is_same_v<AiLayout, tensor_layout::gemm::RowMajor>)
                    {
                        return make_tile_window(a_scale_pad_view[i],
                                                make_tuple(number<TilePartitioner::MPerBlock>{},
                                                           number<KLanePerBlock>{}),
                                                {i_m, 0});
                    }
                    else
                    {
                        return make_tile_window(a_scale_pad_view[i],
                                                make_tuple(number<KLanePerBlock>{},
                                                           number<TilePartitioner::MPerBlock>{}),
                                                {0, i_m});
                    }
                },
                number<NumATensor>{});

            const auto& b_scale_block_window = generate_tuple(
                [&](auto i) {
                    using BiLayout = remove_cvref_t<std::tuple_element_t<i.value, BsLayout>>;
                    if constexpr(GemmPipeline::Preshuffle)
                    {
                        return make_tile_window(
                            b_scale_pad_view[i],
                            make_tuple(number<GemmPipeline::BlockGemmShape::flatNPerWarp>{},
                                       number<GemmPipeline::BlockGemmShape::flatKPerWarp>{}),
                            {static_cast<int>(i_n /
                                              GemmPipeline::BlockGemmShape::WarpTile::at(I1)),
                             0});
                    }
                    else
                    {
                        if constexpr(std::is_same_v<BiLayout, tensor_layout::gemm::ColumnMajor>)
                        {
                            return make_tile_window(b_scale_pad_view[i],
                                                    make_tuple(number<TilePartitioner::NPerBlock>{},
                                                               number<KLanePerBlock>{}),
                                                    {i_n, 0});
                        }
                        else
                        {
                            return make_tile_window(b_scale_pad_view[i],
                                                    make_tuple(number<KLanePerBlock>{},
                                                               number<TilePartitioner::NPerBlock>{}),
                                                    {0, i_n});
                        }
                    }
                },
                number<NumBTensor>{});

            return make_tuple(as_block_window,
                              bs_block_window,
                              e_block_window,
                              a_scale_block_window,
                              b_scale_block_window);
        }
        else
        {
            return make_tuple(as_block_window, bs_block_window, e_block_window);
        }
    }

};
} // namespace ck_tile
