// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Info Technologies Ltd.

#pragma once

#include "ck/utility/common_header.hpp"
#include "ck/tensor_description/tensor_space_filling_curve.hpp"
#include "ck/tensor_description/tensor_descriptor.hpp"
#include "ck/tensor_description/tensor_descriptor_helper.hpp"

namespace ck {

namespace {
// TODO: How to fix this? It uses an struct instead of lambda because lambda
// doesn't have constructor
template <index_t VectorDim, index_t ScalarPerVector>
struct lambda_scalar_per_access
{
    __host__ __device__ constexpr auto operator()(index_t i) const
    {
        return (i == VectorDim) ? ScalarPerVector : 1;
    }
};

template <index_t VectorDim>
struct lambda_scalar_step_in_vector
{
    __host__ __device__ constexpr auto operator()(index_t i) const
    {
        return (i == VectorDim) ? 1 : 0;
    }
};
} // namespace

// Assume:
//   1. src0:
//     1. Src0Desc is known at compile-time
//     2. Src0Buffer is StaticBuffer
//     3. Src0SliceOrginIdx is known at compile-time
//   2. dst:
//     1. DstDesc is not known at compile-time
//     2. DstBuffer is DynamicBuffer
//     3. DstSliceOrginIdx is not known at compile time
//   3. src1 is the same as dst
template <typename Src0Data,
          typename Src1Data,
          typename DstData,
          typename Src0Desc,
          typename Src1Desc,
          typename DstDesc,
          typename ElementwiseOperation,
          typename SliceLengths,
          typename DimAccessOrder,
          index_t DstVectorDim,
          index_t DstScalarPerVector,
          InMemoryDataOperationEnum DstInMemOp,
          bool DstResetCoordinateAfterRun,
          typename enable_if<Src0Desc::IsKnownAtCompileTime(), bool>::type = false>
struct ThreadwiseTensorSliceTransfer_v1r4
{
    static constexpr index_t nDim = SliceLengths::Size();

    using Index = MultiIndex<nDim>;

    using Src1Coord = decltype(make_tensor_coordinate(Src1Desc{}, Index{}));

    using Src1CoordStep = decltype(make_tensor_coordinate_step(Src1Desc{}, Index{}));

    using DstCoord = decltype(make_tensor_coordinate(DstDesc{}, Index{}));

    using DstCoordStep = decltype(make_tensor_coordinate_step(DstDesc{}, Index{}));

    __device__ constexpr ThreadwiseTensorSliceTransfer_v1r4(const Src1Desc& src1_desc,
                                                            const Index& src1_slice_origin_idx,
                                                            const DstDesc& dst_desc,
                                                            const Index& dst_slice_origin_idx,
                                                            const ElementwiseOperation& element_op)
        : src1_coord_(make_tensor_coordinate(src1_desc, src1_slice_origin_idx)),
          dst_coord_(make_tensor_coordinate(dst_desc, dst_slice_origin_idx)),
          element_op_{element_op}
    {
        static_assert(Src0Desc::IsKnownAtCompileTime(),
                      "wrong! SrcDesc need to known at compile-time");
        static_assert(SliceLengths::At(Number<DstVectorDim>{}) % DstScalarPerVector == 0,
                      "wrong! Not divisible");
    }

    __device__ void SetSrc1SliceOrigin(const Src1Desc& src1_desc,
                                       const Index& src1_slice_origin_idx)
    {
        src1_coord_ = make_tensor_coordinate(src1_desc, src1_slice_origin_idx);
    }

    __device__ void SetDstSliceOrigin(const DstDesc& dst_desc, const Index& dst_slice_origin_idx)
    {
        dst_coord_ = make_tensor_coordinate(dst_desc, dst_slice_origin_idx);
    }

    template <typename Src0SliceOriginIdx,
              typename Src0Buffer,
              typename Src1Buffer,
              typename DstBuffer>
    __device__ void Run(const Src0Desc&,
                        const Src0SliceOriginIdx&,
                        const Src0Buffer& src0_buf,
                        const Src1Desc& src1_desc,
                        const Src1Buffer& src1_buf,
                        const DstDesc& dst_desc,
                        DstBuffer& dst_buf)
    {
        static_assert(Src0Desc::IsKnownAtCompileTime(),
                      "wrong! Src0Desc need to known at compile-time");

        static_assert(is_known_at_compile_time<remove_cvref_t<Src0SliceOriginIdx>>::value,
                      "wrong! Src0SliceOrigin need to known at compile-time");

        static_assert(Src0Buffer::IsStaticBuffer(), "wrong! Src0Buffer need to be StaticBuffer");

        // Src0Desc and src0_slice_origin_idx are known at compile-time
        constexpr auto src0_desc             = remove_cvref_t<Src0Desc>{};
        constexpr auto src0_slice_origin_idx = to_multi_index(Src0SliceOriginIdx{});

        // scalar per access on each dim
        // TODO: don't use lambda_scalar_per_access
        constexpr auto dst_scalar_per_access = generate_sequence(
            lambda_scalar_per_access<DstVectorDim, DstScalarPerVector>{}, Number<nDim>{});

        constexpr auto dst_scalar_step_in_vector =
            generate_sequence(lambda_scalar_step_in_vector<DstVectorDim>{}, Number<nDim>{});

        using SpaceFillingCurve = SpaceFillingCurve<SliceLengths,
                                                    DimAccessOrder,
                                                    remove_cv_t<decltype(dst_scalar_per_access)>>;

        // TODO: Use SpaceFillingCurve::ScalarsPerAccess instread of DstScalarPerVector?
        static_assert(DstScalarPerVector == SpaceFillingCurve::ScalarPerVector,
                      "wrong!DstScalarPerVector != SpaceFillingCurve::ScalarPerVector");

        using src1_vector_type = vector_type_maker_t<Src1Data, DstScalarPerVector>;
        using src1_vector_t    = typename src1_vector_type::type;
        src1_vector_type src1_vector;

        using dst_vector_type = vector_type_maker_t<DstData, DstScalarPerVector>;
        using dst_vector_t    = typename dst_vector_type::type;
        dst_vector_type dst_vector;

        constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();

        static_for<0, num_access, 1>{}([&](auto idx_1d) {
            constexpr auto idx_md = SpaceFillingCurve::GetIndex(idx_1d);

            // copy data from src0_buf into src0_vector
            static_for<0, DstScalarPerVector, 1>{}([&](auto i) {
                constexpr index_t src0_offset = src0_desc.CalculateOffset(
                    src0_slice_origin_idx + idx_md + i * dst_scalar_step_in_vector);

                // apply type convert
                dst_vector.template AsType<DstData>()(i) =
                    type_convert<DstData>(src0_buf[Number<src0_offset>{}]);
            });

            const bool is_src1_valid =
                coordinate_has_valid_offset_assuming_visible_index_is_valid(src1_desc, src1_coord_);

            // copy data from src1_buf into src1_vector
            auto src1_vector_tmp = src1_vector_type{
                src1_buf.template Get<src1_vector_t>(src1_coord_.GetOffset(), is_src1_valid)};

            // apply type convert
            static_for<0, DstScalarPerVector, 1>{}([&](auto i) {
                src1_vector.template AsType<DstData>()(i) =
                    type_convert<DstData>(src1_vector_tmp.template AsType<Src1Data>()[i]);
            });

            // apply pointwise operation
            static_for<0, DstScalarPerVector, 1>{}([&](auto i) {
                element_op_(dst_vector.template AsType<DstData>()(i),
                            dst_vector.template AsType<DstData>()[i],
                            src1_vector.template AsType<DstData>()[i]);
            });

            const bool is_dst_valid =
                coordinate_has_valid_offset_assuming_visible_index_is_valid(dst_desc, dst_coord_);

            // copy data from dst_vector into dst_buf
            dst_buf.template Update<DstInMemOp, dst_vector_t>(
                dst_coord_.GetOffset(),
                is_dst_valid,
                dst_vector.template AsType<dst_vector_t>()[Number<0>{}]);

            if constexpr(idx_1d.value != num_access - 1)
            {
                constexpr auto forward_step = SpaceFillingCurve::GetForwardStep(idx_1d);

                move_tensor_coordinate(
                    dst_desc, dst_coord_, make_tensor_coordinate_step(dst_desc, forward_step));

                move_tensor_coordinate(
                    src1_desc, src1_coord_, make_tensor_coordinate_step(src1_desc, forward_step));
            }
        });

        // move dst coordinate back to slice origin (or not)
        if constexpr(DstResetCoordinateAfterRun)
        {
            const auto dst_reset_step =
                make_tensor_coordinate_step(dst_desc, GetDstCoordinateResetStep());

            move_tensor_coordinate(dst_desc, dst_coord_, dst_reset_step);

            move_tensor_coordinate(src1_desc, src1_coord_, dst_reset_step);
        }
    }

    __device__ static constexpr auto GetDstCoordinateResetStep()
    {
        constexpr auto dst_scalar_per_access = generate_sequence(
            lambda_scalar_per_access<DstVectorDim, DstScalarPerVector>{}, Number<nDim>{});

        using SpaceFillingCurve = SpaceFillingCurve<SliceLengths,
                                                    DimAccessOrder,
                                                    remove_cv_t<decltype(dst_scalar_per_access)>>;

        constexpr auto num_access = SpaceFillingCurve::GetNumOfAccess();
        if constexpr(num_access == 0)
        {
            return typename SpaceFillingCurve::Index{};
        }
        else
        {
            constexpr auto reset_step =
                SpaceFillingCurve::GetStepBetween(Number<num_access - 1>{}, Number<0>{});

            return reset_step;
        }
    }

    // dst_slice_origin_step_idx need to be known at compile-time, for performance reason
    __device__ void MoveDstSliceWindow(const DstDesc& dst_desc,
                                       const Index& dst_slice_origin_step_idx)
    {
        // if dst coord was not reset by Run(), then need to adjust the step here
        const auto adjusted_step_idx =
            DstResetCoordinateAfterRun ? dst_slice_origin_step_idx
                                       : dst_slice_origin_step_idx + GetDstCoordinateResetStep();

        // is it OK to construct a new step every time?
        const auto adjusted_step = make_tensor_coordinate_step(dst_desc, adjusted_step_idx);

        move_tensor_coordinate(dst_desc, dst_coord_, adjusted_step);
    }

    // src1_slice_origin_step_idx need to be known at compile-time, for performance reason
    __device__ void MoveDstSliceWindow(const Src1Desc& src1_desc,
                                       const Index& src1_slice_origin_step_idx)
    {
        // if dst coord was not reset by Run(), then need to adjust the step here
        const auto adjusted_step_idx =
            DstResetCoordinateAfterRun ? src1_slice_origin_step_idx
                                       : src1_slice_origin_step_idx + GetDstCoordinateResetStep();

        // is it OK to construct a new step every time?
        const auto adjusted_step = make_tensor_coordinate_step(src1_desc, adjusted_step_idx);

        move_tensor_coordinate(src1_desc, src1_coord_, adjusted_step);
    }

    private:
    Src1Coord src1_coord_;
    DstCoord dst_coord_;
    const ElementwiseOperation element_op_;
}; // namespace ThreadwiseTensorSliceTransfer_v1r4

} // namespace ck
