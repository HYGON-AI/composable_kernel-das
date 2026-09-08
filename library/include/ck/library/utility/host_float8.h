// SPDX-License-Identifier: MIT
// Copyright (c) 2018-2022, Advanced Micro Devices, Inc. All rights reserved.

/*!
    \file
    \brief Defines a class for using IEEE half-precision floating-point types in host or
      device code.
*/

#pragma once

#ifdef __GNUC__
// Ignore checks on reinterpret-casts that are being used for bitcasts.
#pragma GCC diagnostic ignored "-Wstrict-aliasing"
#endif

#include <cmath>
#include <limits>
#include <cstdint>
#include <cstring>

namespace ck {
namespace host {

///////////////////////////////////////////////////////////////////////////////////////////////////
//
//  FP8 Has 2 encodings possible : E4M3 and E5M2
//
//  E4M3 : 7  |  6 5 4 3  |  2 1 0
//  E5M2 : 7  |  6 5 4 3 2  |  1 0
//
///////////////////////////////////////////////////////////////////////////////////////////////////

enum class FloatEncoding
{
    E4M3,
    E5M2
};

template <FloatEncoding T>
struct alignas(1) float8_base
{

    static constexpr bool IS_E4M3 = (T == FloatEncoding::E4M3);
    static constexpr bool IS_E5M2 = (T == FloatEncoding::E5M2);

    // Number of Bits representing mantissa and exponents
    static constexpr int FP32_NUM_BITS           = 32;
    static constexpr int FP32_NUM_EXPONENT_BITS  = 8;
    static constexpr int FP32_NUM_MANTISSA_BITS  = 23;
    static constexpr uint32_t FP32_NAN           = 0x7fffffff;
    static constexpr uint32_t FP32_INFINITY_MASK = 0x7f800000;
    static constexpr int FP32_MAX_EXPONENT       = 127;
    static constexpr int FP32_MIN_EXPONENT       = -126;
    static constexpr int FP32_EXPONENT_BIAS      = 127;

    static constexpr int FP16_NUM_BITS           = 16;
    static constexpr int FP16_NUM_EXPONENT_BITS  = 5;
    static constexpr int FP16_NUM_MANTISSA_BITS  = 10;
    static constexpr uint16_t FP16_NAN           = 0x7fff;
    static constexpr uint16_t FP16_INFINITY_MASK = 0x7c00;
    static constexpr int FP16_MAX_EXPONENT       = 15;
    static constexpr int FP16_MIN_EXPONENT       = -14;
    static constexpr int FP16_EXPONENT_BIAS      = 15;

    static constexpr int FP8_NUM_BITS          = 8;
    static constexpr int FP8_NUM_EXPONENT_BITS = IS_E4M3 ? 4 : 5;
    static constexpr int FP8_NUM_MANTISSA_BITS = IS_E4M3 ? 3 : 2;
    static constexpr uint8_t FP8_NAN           = 0x7f; // Also F8_INF
    static constexpr uint8_t FP8_INFINITY_MASK = IS_E4M3 ? 0x78 : 0x7c;
    static constexpr int FP8_MAX_EXPONENT      = IS_E4M3 ? 7 : 15;
    static constexpr int FP8_MIN_EXPONENT      = IS_E4M3 ? -6 : -14;
    static constexpr int FP8_EXPONENT_BIAS     = IS_E4M3 ? 7 : 15;

    static constexpr uint8_t FP8_EXPONENT_MASK = (1 << FP8_NUM_EXPONENT_BITS) - 1;
    static constexpr uint8_t FP8_MANTISSA_MASK = (1 << FP8_NUM_MANTISSA_BITS) - 1;

    static constexpr uint8_t FP8_MAX_FLT = (IS_E4M3 ? 0x7e : 0x7b);

    // 256 in float
    static constexpr uint32_t FP8_SAT_VAL_FP32 = 0x43800000;

    //
    // Data members
    //

    /// Data container
    uint8_t storage;

    /// Ctors.

    float8_base() : storage(0) {}

    /// Is finite implementation

    static bool isfinite(float flt)
    {
        uint32_t s;

        std::memcpy(&s, &flt, sizeof(s));

        return (s & 0x7f800000) < 0x7f800000;
    }

    /// Is NaN implementation

    static bool isnan(float flt)
    {
        uint32_t s;

        std::memcpy(&s, &flt, sizeof(s));

        return (s & 0x7fffffff) > 0x7f800000;
    }

    /// Is infinite implementation

    static bool isinf(float flt)
    {
        uint32_t s;

        std::memcpy(&s, &flt, sizeof(s));

        // Sign = 0 for +inf, 1 for -inf
        // Exponent = all ones
        // Mantissa = all zeros
        return (s == 0x7f800000) || (s == 0xff800000);
    }

    /// FP32 -> FP8 conversion - rounds to nearest even

    static uint8_t convert_float_to_fp8(float const& flt)
    {

        // software implementation rounds toward nearest even
        uint32_t s;

        std::memcpy(&s, &flt, sizeof(s));

        // Extract the bits in the FP32 type
        uint8_t sign = uint8_t((s >> 24 & 0x80));
        int8_t exp   = uint8_t(((s >> FP32_NUM_MANTISSA_BITS) & 0xff) - FP32_EXPONENT_BIAS);
        int mantissa = s & 0x7fffff;
        uint8_t u    = 0;

        uint8_t const kF8_NaN = 0x7f;

        // NaN => NaN
        if(isnan(flt))
        {
            return kF8_NaN;
        }

        // Inf => MAX_FLT (satfinite)
        if(isinf(flt))
        {
            return sign | FP8_MAX_FLT;
        }

        // Special handling
        if(exp == -128)
        {
            // int8 range is from -128 to 127
            // So 255(inf) - 127(bias) = 128 - will show up as -128

            // satfinite
            return (sign | FP8_MAX_FLT);
        }

        int sticky_bit = 0;

        bool skip_sign  = false;
        bool may_be_nan = false;

        if((exp >= FP8_MIN_EXPONENT) && (exp <= FP8_MAX_EXPONENT))
        {
            // normal fp32 to normal fp8
            exp = uint8_t(exp + uint8_t(FP8_EXPONENT_BIAS));
            u   = uint8_t(((exp & FP8_EXPONENT_MASK) << FP8_NUM_MANTISSA_BITS));
            u   = uint8_t(u | (mantissa >> (FP32_NUM_MANTISSA_BITS - FP8_NUM_MANTISSA_BITS)));
        }
        else if(exp < FP8_MIN_EXPONENT)
        {
            // normal single-precision to subnormal float8-precision representation
            int rshift = (FP8_MIN_EXPONENT - exp);
            if(rshift < FP32_NUM_BITS)
            {
                mantissa |= (1 << FP32_NUM_MANTISSA_BITS);

                sticky_bit = ((mantissa & ((1 << rshift) - 1)) != 0);

                mantissa = (mantissa >> rshift);
                u        = (uint8_t(mantissa >> (FP32_NUM_MANTISSA_BITS - FP8_NUM_MANTISSA_BITS)) &
                     FP8_MANTISSA_MASK);
            }
            else
            {
                mantissa = 0;
                u        = 0;
            }
            // Exponent > FP8_MAX_EXPONENT - this is a special case done to match HW
            // 0x4380_0000 to 0x43e0_0000 - maps from 256 to 448, and does not saturate / inf.
        }
        else
        {
            if(exp == (FP8_MAX_EXPONENT + 1))
            {
                uint8_t mantissa_tmp =
                    uint8_t(mantissa >> (FP32_NUM_MANTISSA_BITS - FP8_NUM_MANTISSA_BITS));
                if(mantissa_tmp < FP8_MANTISSA_MASK)
                {
                    exp        = uint8_t(exp + uint8_t(FP8_EXPONENT_BIAS));
                    u          = uint8_t(exp << FP8_NUM_MANTISSA_BITS) | mantissa_tmp;
                    may_be_nan = (mantissa_tmp == (FP8_MANTISSA_MASK - 1));
                }
                else
                {
                    // satfinite
                    return (sign | FP8_MAX_FLT);
                }
            }
            else
            {
                // satfinite
                return (sign | FP8_MAX_FLT);
            }
        }

        // round to nearest even
        int NUM_BITS_SHIFT = FP32_NUM_MANTISSA_BITS - (FP8_NUM_MANTISSA_BITS + 1);
        int round_bit      = ((mantissa >> NUM_BITS_SHIFT) & 1);
        sticky_bit |= ((mantissa & ((1 << NUM_BITS_SHIFT) - 1)) != 0);

        if((round_bit && sticky_bit) || (round_bit && (u & 1)))
        {
            u = uint8_t(u + 1);
            if(may_be_nan)
            {
                skip_sign = true;
            }
        }

        if(u > FP8_MAX_FLT)
        {
            // satfinite
            u = (sign | FP8_MAX_FLT);
        }

        if(!skip_sign)
        {
            u |= sign;
        }

        return u;
    }

    /// Converts a fp8 value stored as a uint8_t to a float

    static float convert_fp8_to_float(uint8_t const& x)
    {

        uint32_t constexpr kF32_NaN = 0x7fffffff;

        uint8_t const& f8 = x;
        int sign          = (f8 >> (FP8_NUM_BITS - 1)) & 1;
        int exp           = (f8 >> FP8_NUM_MANTISSA_BITS) & FP8_EXPONENT_MASK;
        int mantissa      = f8 & FP8_MANTISSA_MASK;
        unsigned f        = (sign << (FP32_NUM_BITS - 1));

        if(IS_E4M3 && exp == 15 && mantissa == 0x7)
        {
            f = kF32_NaN;
        }
        else if(exp > 0 && (IS_E4M3 || exp < (FP8_MAX_EXPONENT + FP8_EXPONENT_BIAS + 1)))
        {
            // normal
            exp += (FP32_EXPONENT_BIAS - FP8_EXPONENT_BIAS);
            f = f | (exp << FP32_NUM_MANTISSA_BITS) |
                (mantissa << (FP32_NUM_MANTISSA_BITS - FP8_NUM_MANTISSA_BITS));
        }
        else if(exp == 0)
        {
            if(mantissa)
            {
                // subnormal
                exp += (FP32_EXPONENT_BIAS - FP8_EXPONENT_BIAS) + 1;
                while((mantissa & (1 << FP8_NUM_MANTISSA_BITS)) == 0)
                {
                    mantissa <<= 1;
                    exp--;
                }
                mantissa &= FP8_MANTISSA_MASK;
                f = f | (exp << FP32_NUM_MANTISSA_BITS) |
                    (mantissa << (FP32_NUM_MANTISSA_BITS - FP8_NUM_MANTISSA_BITS));
            }
            else
            {
                // sign-preserving zero
            }
        }
        else
        {
            if(mantissa == 0)
            {
                // Sign-preserving infinity
                f = (f | 0x7f800000);
            }
            else
            {
                // Canonical NaN
                f = kF32_NaN;
            }
        }

        float flt;
        std::memcpy(&flt, &f, sizeof(flt));
        return flt;
    }
};

// Forward declaration of bf8_t to define fp8_t <=> bf8_t
// conversions in class fp8_t
struct bf8_t;

///////////////////////////////////////////////////////////////
///
/// floating-point 8 type : E4M3
///
///////////////////////////////////////////////////////////////
struct alignas(1) fp8_t : float8_base<FloatEncoding::E4M3>
{

    using Base = float8_base<FloatEncoding::E4M3>;

    static constexpr int MAX_EXPONENT = Base::FP8_MAX_EXPONENT;

    //
    // Static conversion operators
    //

    /// Constructs from an uint8_t

    static fp8_t bitcast(uint8_t x)
    {
        fp8_t f;
        f.storage = x;
        return f;
    }

    /// FP32 -> FP8 conversion - rounds to nearest even

    static fp8_t from_float(float const& flt)
    {
        return bitcast(Base::convert_float_to_fp8(flt));
    }

    // E4M3 -> Float

    static float to_float(fp8_t const& x) { return Base::convert_fp8_to_float(x.storage); }

    //
    // Methods
    //

    /// Constructor inheritance
    using Base::Base;

    /// Default constructor
    fp8_t() = default;

    /// Floating point conversion

    explicit fp8_t(float x) { storage = from_float(x).storage; }

    //
    // explicit fp8_t(half x) {
    //     storage = from_half(x).storage;
    // }

    /// Floating point conversion

    explicit fp8_t(double x) : fp8_t(float(x)) {}

    /// Integer conversion

    explicit fp8_t(int x) : fp8_t(float(x)) {}

    /// E5M2 conversion. Defined after bf8_t is defined.

    explicit fp8_t(bf8_t x);

    /// Converts to float

    operator float() const { return to_float(*this); }

    /// Converts to float

    explicit operator double() const { return double(to_float(*this)); }

    /// Converts to int

    explicit operator int() const { return int(to_float(*this)); }

    /// Casts to bool

    explicit operator bool() const { return bool(int(to_float(*this))); }

    /// Accesses raw internal state

    uint8_t& raw() { return storage; }

    /// Accesses raw internal state

    uint8_t raw() const { return storage; }

    /// Returns the sign bit

    bool signbit() const { return ((storage & (1 << (Base::FP8_NUM_BITS - 1))) != 0); }

    /// Returns the biased exponent

    int exponent_biased() const
    {
        return int((storage >> FP8_NUM_MANTISSA_BITS) & Base::FP8_EXPONENT_MASK);
    }

    /// Returns the unbiased exponent

    int exponent() const { return exponent_biased() - 15; }

    /// Returns the mantissa

    int mantissa() const { return int(storage & Base::FP8_MANTISSA_MASK); }
};
///////////////////////////////////////////////////////////////
///
/// floating-point 8 type : E5M2
///
///////////////////////////////////////////////////////////////
struct alignas(1) bf8_t : float8_base<FloatEncoding::E5M2>
{

    using Base = float8_base<FloatEncoding::E5M2>;

    static constexpr int MAX_EXPONENT = Base::FP8_MAX_EXPONENT;

    //
    // Static conversion operators
    //

    /// Constructs from an uint8_t

    static bf8_t bitcast(uint8_t x)
    {
        bf8_t f;
        f.storage = x;
        return f;
    }

    /// FP32 -> FP8 conversion - rounds to nearest even

    static bf8_t from_float(float const& flt)
    {
        return bitcast(Base::convert_float_to_fp8(flt));
    }

    // E5M2 -> Float

    static float to_float(bf8_t const& x) { return Base::convert_fp8_to_float(x.storage); }

    //
    // Methods
    //

    /// Constructor inheritance
    using Base::Base;

    /// Default constructor
    bf8_t() = default;

    /// Floating point conversion

    explicit bf8_t(float x) { storage = from_float(x).storage; }

    //
    // explicit bf8_t(half x) {
    //   storage = from_half(x).storage;
    // }

    /// Floating point conversion

    explicit bf8_t(double x) : bf8_t(float(x)) {}

    /// Integer conversion

    explicit bf8_t(int x) : bf8_t(float(x)) {}

    /// E4M3 conversion

    explicit bf8_t(fp8_t x);

    /// Converts to float

    operator float() const { return to_float(*this); }

    /// Converts to float

    explicit operator double() const { return double(to_float(*this)); }

    /// Converts to int

    explicit operator int() const { return int(to_float(*this)); }

    /// Casts to bool

    explicit operator bool() const { return bool(int(to_float(*this))); }

    /// Accesses raw internal state

    uint8_t& raw() { return storage; }

    /// Accesses raw internal state

    uint8_t raw() const { return storage; }

    /// Returns the sign bit

    bool signbit() const { return ((storage & (1 << (Base::FP8_NUM_BITS - 1))) != 0); }

    /// Returns the biased exponent

    int exponent_biased() const
    {
        return int((storage >> FP8_NUM_MANTISSA_BITS) & Base::FP8_EXPONENT_MASK);
    }

    /// Returns the unbiased exponent

    int exponent() const { return exponent_biased() - 15; }

    /// Returns the mantissa

    int mantissa() const { return int(storage & Base::FP8_MANTISSA_MASK); }
};
///////////////////////////////////////////////////////////////////////////////////////////////////
//
// Arithmetic operators
//
///////////////////////////////////////////////////////////////////////////////////////////////////

bool operator<(fp8_t const& lhs, fp8_t const& rhs) { return float(lhs) < float(rhs); }

bool operator<=(fp8_t const& lhs, fp8_t const& rhs)
{
    return float(lhs) <= float(rhs);
}

bool operator>(fp8_t const& lhs, fp8_t const& rhs) { return float(lhs) > float(rhs); }

bool operator>=(fp8_t const& lhs, fp8_t const& rhs)
{
    return float(lhs) >= float(rhs);
}

fp8_t operator+(fp8_t const& lhs, fp8_t const& rhs)
{
    return fp8_t(float(lhs) + float(rhs));
}

fp8_t operator-(fp8_t const& lhs) { return fp8_t(-float(lhs)); }

fp8_t operator-(fp8_t const& lhs, fp8_t const& rhs)
{
    return fp8_t(float(lhs) - float(rhs));
}

fp8_t operator*(fp8_t const& lhs, fp8_t const& rhs)
{
    return fp8_t(float(lhs) * float(rhs));
}

fp8_t operator/(fp8_t const& lhs, fp8_t const& rhs)
{
    return fp8_t(float(lhs) / float(rhs));
}

fp8_t& operator+=(fp8_t& lhs, fp8_t const& rhs)
{
    lhs = fp8_t(float(lhs) + float(rhs));
    return lhs;
}

fp8_t& operator-=(fp8_t& lhs, fp8_t const& rhs)
{
    lhs = fp8_t(float(lhs) - float(rhs));
    return lhs;
}

fp8_t& operator*=(fp8_t& lhs, fp8_t const& rhs)
{
    lhs = fp8_t(float(lhs) * float(rhs));
    return lhs;
}

fp8_t& operator/=(fp8_t& lhs, fp8_t const& rhs)
{
    lhs = fp8_t(float(lhs) / float(rhs));
    return lhs;
}

fp8_t& operator++(fp8_t& lhs)
{
    float tmp(lhs);
    ++tmp;
    lhs = fp8_t(tmp);
    return lhs;
}

fp8_t& operator--(fp8_t& lhs)
{
    float tmp(lhs);
    --tmp;
    lhs = fp8_t(tmp);
    return lhs;
}

fp8_t operator++(fp8_t& lhs, int)
{
    fp8_t ret(lhs);
    float tmp(lhs);
    tmp++;
    lhs = fp8_t(tmp);
    return ret;
}

fp8_t operator--(fp8_t& lhs, int)
{
    fp8_t ret(lhs);
    float tmp(lhs);
    tmp--;
    lhs = fp8_t(tmp);
    return ret;
}

bool operator<(bf8_t const& lhs, bf8_t const& rhs) { return float(lhs) < float(rhs); }

bool operator<=(bf8_t const& lhs, bf8_t const& rhs)
{
    return float(lhs) <= float(rhs);
}

bool operator>(bf8_t const& lhs, bf8_t const& rhs) { return float(lhs) > float(rhs); }

bool operator>=(bf8_t const& lhs, bf8_t const& rhs)
{
    return float(lhs) >= float(rhs);
}

bf8_t operator+(bf8_t const& lhs, bf8_t const& rhs)
{
    return bf8_t(float(lhs) + float(rhs));
}

bf8_t operator-(bf8_t const& lhs) { return bf8_t(-float(lhs)); }

bf8_t operator-(bf8_t const& lhs, bf8_t const& rhs)
{
    return bf8_t(float(lhs) - float(rhs));
}

bf8_t operator*(bf8_t const& lhs, bf8_t const& rhs)
{
    return bf8_t(float(lhs) * float(rhs));
}

bf8_t operator/(bf8_t const& lhs, bf8_t const& rhs)
{
    return bf8_t(float(lhs) / float(rhs));
}

bf8_t& operator+=(bf8_t& lhs, bf8_t const& rhs)
{
    lhs = bf8_t(float(lhs) + float(rhs));
    return lhs;
}

bf8_t& operator-=(bf8_t& lhs, bf8_t const& rhs)
{
    lhs = bf8_t(float(lhs) - float(rhs));
    return lhs;
}

bf8_t& operator*=(bf8_t& lhs, bf8_t const& rhs)
{
    lhs = bf8_t(float(lhs) * float(rhs));
    return lhs;
}

bf8_t& operator/=(bf8_t& lhs, bf8_t const& rhs)
{
    lhs = bf8_t(float(lhs) / float(rhs));
    return lhs;
}

bf8_t& operator++(bf8_t& lhs)
{
    float tmp(lhs);
    ++tmp;
    lhs = bf8_t(tmp);
    return lhs;
}

bf8_t& operator--(bf8_t& lhs)
{
    float tmp(lhs);
    --tmp;
    lhs = bf8_t(tmp);
    return lhs;
}

bf8_t operator++(bf8_t& lhs, int)
{
    bf8_t ret(lhs);
    float tmp(lhs);
    tmp++;
    lhs = bf8_t(tmp);
    return ret;
}

bf8_t operator--(bf8_t& lhs, int)
{
    bf8_t ret(lhs);
    float tmp(lhs);
    tmp--;
    lhs = bf8_t(tmp);
    return ret;
}

///////////////////////////////////////////////////////////////////////////////////////////////////
//
// fp8_t <=> bf8_t conversions
//
///////////////////////////////////////////////////////////////////////////////////////////////////

/// fp8_t <= bf8_t

fp8_t::fp8_t(bf8_t x)
{
    storage = from_float(bf8_t::to_float(x)).storage;
}

/// bf8_t <= fp8_t

bf8_t::bf8_t(fp8_t x)
{
    storage = from_float(fp8_t::to_float(x)).storage;
}

} // namespace host
} // namespace ck

///////////////////////////////////////////////////////////////////////////////////////////////////
//
// Standard Library operations and definitions
//
///////////////////////////////////////////////////////////////////////////////////////////////////

namespace std {

/// Numeric limits common to all float8 types
template <typename T>
struct float8_base_numeric_limits
{
    private:
    using F8Type = T;

    public:
    static bool const is_specialized                = true;
    static bool const is_signed                     = true;
    static bool const is_integer                    = false;
    static bool const is_exact                      = false;
    static bool const has_quiet_NaN                 = true;
    static bool const has_signaling_NaN             = false;
    static std::float_denorm_style const has_denorm = std::denorm_present;
    static bool const has_denorm_loss               = true;
    static std::float_round_style const round_style = std::round_to_nearest;
    static bool const is_iec559                     = false;
    static bool const is_bounded                    = true;
    static bool const is_modulo                     = false;
    static int const digits                         = F8Type::FP8_NUM_MANTISSA_BITS;

    /// Least positive value
    static F8Type min() { return F8Type::bitcast(0x01); }

    /// Maximum finite value
    static F8Type max() { return F8Type::bitcast(F8Type::FP8_MAX_FLT); }

    /// Returns maximum rounding error
    static F8Type round_error() { return F8Type(0.5f); }

    /// Returns positive infinity value
    static F8Type infinity() { return F8Type::bitcast(F8Type::FP8_INFINITY_MASK); }

    /// Returns quiet NaN value
    static F8Type quiet_NaN() { return F8Type::bitcast(F8Type::FP8_NAN); }

    /// Returns signaling NaN value
    static F8Type signaling_NaN() { return F8Type::bitcast(F8Type::FP8_NAN); }

    /// Returns smallest positive subnormal value
    static F8Type denorm_min() { return F8Type::bitcast(0x01); }
};

/// Numeric limits for fp8_t
template <>
struct numeric_limits<ck::host::fp8_t> : public float8_base_numeric_limits<ck::host::fp8_t>
{
    static bool const has_infinity = false;

    /// Minimum finite value
    static ck::host::fp8_t lowest() { return ck::host::fp8_t::bitcast(0xfe); }

    /// Machine epsilon, that is, the difference between 1.0 and the next representable value
    static ck::host::fp8_t epsilon() { return ck::host::fp8_t::bitcast(0x20); }
};

/// Numeric limits for bf8_t
template <>
struct numeric_limits<ck::host::bf8_t> : public float8_base_numeric_limits<ck::host::bf8_t>
{
    static bool const has_infinity = true;

    /// Minimum finite value
    static ck::host::bf8_t lowest() { return ck::host::bf8_t::bitcast(0xfb); }

    /// Machine epsilon, that is, the difference between 1.0 and the next representable value
    static ck::host::bf8_t epsilon() { return ck::host::bf8_t::bitcast(0x34); }
};

} // namespace std

namespace platform {

/// Numeric limits common to all float8 types
template <typename T>
struct float8_base_numeric_limits
{
    private:
    using F8Type = T;

    public:
    static bool const is_specialized                = true;
    static bool const is_signed                     = true;
    static bool const is_integer                    = false;
    static bool const is_exact                      = false;
    static bool const has_quiet_NaN                 = true;
    static bool const has_signaling_NaN             = false;
    static std::float_denorm_style const has_denorm = std::denorm_present;
    static bool const has_denorm_loss               = true;
    static std::float_round_style const round_style = std::round_to_nearest;
    static bool const is_iec559                     = false;
    static bool const is_bounded                    = true;
    static bool const is_modulo                     = false;
    static int const digits                         = F8Type::FP8_NUM_MANTISSA_BITS;

    /// Least positive value
    static F8Type min() { return F8Type::bitcast(0x01); }

    /// Maximum finite value
    static F8Type max() { return F8Type::bitcast(F8Type::FP8_MAX_FLT); }

    /// Returns maximum rounding error
    static F8Type round_error() { return F8Type(0.5f); }

    /// Returns positive infinity value
    static F8Type infinity() { return F8Type::bitcast(F8Type::FP8_INFINITY_MASK); }

    /// Returns quiet NaN value
    static F8Type quiet_NaN() { return F8Type::bitcast(F8Type::FP8_NAN); }

    /// Returns signaling NaN value
    static F8Type signaling_NaN() { return F8Type::bitcast(F8Type::FP8_NAN); }

    /// Returns smallest positive subnormal value
    static F8Type denorm_min() { return F8Type::bitcast(0x01); }
};

/// std::numeric_limits
template <class T>
struct numeric_limits;

/// Numeric limits for fp8_t
template <>
struct numeric_limits<ck::host::fp8_t> : public float8_base_numeric_limits<ck::host::fp8_t>
{
    static bool const has_infinity = false;

    /// Minimum finite value
    static ck::host::fp8_t lowest() { return ck::host::fp8_t::bitcast(0xfe); }

    /// Machine epsilon, that is, the difference between 1.0 and the next representable value
    static ck::host::fp8_t epsilon() { return ck::host::fp8_t::bitcast(0x20); }
};

/// Numeric limits for bf8_t
template <>
struct numeric_limits<ck::host::bf8_t> : public float8_base_numeric_limits<ck::host::bf8_t>
{
    static bool const has_infinity = true;

    /// Minimum finite value
    static ck::host::bf8_t lowest() { return ck::host::bf8_t::bitcast(0xfb); }

    /// Machine epsilon, that is, the difference between 1.0 and the next representable value
    static ck::host::bf8_t epsilon() { return ck::host::bf8_t::bitcast(0x34); }
};

} // namespace platform

///////////////////////////////////////////////////////////////////////////////////////////////////

//
// User-defined literals
//

ck::host::fp8_t operator""_fe4m3(long double x) { return ck::host::fp8_t(float(x)); }

ck::host::fp8_t operator""_fe4m3(unsigned long long int x) { return ck::host::fp8_t(int(x)); }

ck::host::bf8_t operator""_fe5m2(long double x) { return ck::host::bf8_t(float(x)); }

ck::host::bf8_t operator""_fe5m2(unsigned long long int x) { return ck::host::bf8_t(int(x)); }

/////////////////////////////////////////////////////////////////////////////////////////////////
