/*  Written in 2019 by David Blackman and Sebastiano Vigna (vigna@acm.org)

To the extent possible under law, the author has dedicated all copyright
and related and neighboring rights to this software to the public domain
worldwide.

Permission to use, copy, modify, and/or distribute this software for any
purpose with or without fee is hereby granted.

THE SOFTWARE IS PROVIDED "AS IS" AND THE AUTHOR DISCLAIMS ALL WARRANTIES
WITH REGARD TO THIS SOFTWARE INCLUDING ALL IMPLIED WARRANTIES OF
MERCHANTABILITY AND FITNESS. IN NO EVENT SHALL THE AUTHOR BE LIABLE FOR
ANY SPECIAL, DIRECT, INDIRECT, OR CONSEQUENTIAL DAMAGES OR ANY DAMAGES
WHATSOEVER RESULTING FROM LOSS OF USE, DATA OR PROFITS, WHETHER IN AN
ACTION OF CONTRACT, NEGLIGENCE OR OTHER TORTIOUS ACTION, ARISING OUT OF OR
IN CONNECTION WITH THE USE OR PERFORMANCE OF THIS SOFTWARE.

Ported to C++, vectorized, and optimized by Marco Barbone.
Original implementation by David Blackman and Sebastiano
Vigna.
*/

#pragma once

#include <array>
#include <cstdint>
#include <cstring>
#include <limits>
#include <memory>

#include <poet/poet.hpp>

#include "dispatch_arch.hpp"
#include "macros.hpp"
#include "xoshiro_scalar.hpp"

namespace simdrng {

class XoshiroSIMD;

namespace internal {

/**
 * SIMD state for the vectorized Xoshiro256++ generator.
 * Contains the 4 SIMD register state and all PRNG operations.
 *
 * @tparam Arch The xsimd architecture type.
 */
template <class Arch> struct XoshiroState {
  using result_type = std::uint64_t;
  using simd_type = xsimd::batch<result_type, Arch>;
  static constexpr std::uint8_t RNG_WIDTH = 4;
  static constexpr std::uint8_t SIMD_WIDTH = simd_type::size;
  static constexpr std::uint16_t CACHE_SIZE = std::numeric_limits<std::uint8_t>::max() + 1;

  alignas(simd_type::arch_type::alignment()) std::array<simd_type, RNG_WIDTH> s{};

  /**
   * Seed the SIMD state from a scalar seed. Lane i is the base state after
   * i jumps of 2^128 outputs, so the lanes hold disjoint streams.
   */
  SIMDRNG_ALWAYS_INLINE constexpr void seed(result_type seed_val) noexcept {
    XoshiroScalar rng{seed_val};
    std::array<std::array<result_type, SIMD_WIDTH>, RNG_WIDTH> states{};
    for (auto i = 0UL; i < SIMD_WIDTH; ++i) {
      for (auto j = 0UL; j < RNG_WIDTH; ++j) {
        states[j][i] = rng.getState()[j];
      }
      rng.jump();
    }
    poet::static_for<0, RNG_WIDTH>([&](auto I) { s[I] = simd_type::load_unaligned(states[I].data()); });
  }

  SIMDRNG_ALWAYS_INLINE constexpr simd_type next() noexcept {
    const auto result = xsimd::rotl<23>(s[0] + s[3]) + s[0];
    const auto t = xsimd::bitwise_lshift<17>(s[1]);

    s[2] ^= s[0];
    s[3] ^= s[1];

    s[1] ^= s[2];
    s[0] ^= s[3];

    s[2] ^= t;

    s[3] = xsimd::rotl<45>(s[3]);

    return result;
  }

  SIMDRNG_ALWAYS_INLINE constexpr void
  populate_cache(std::array<result_type, CACHE_SIZE> &SIMDRNG_RESTRICT cache) noexcept {
    poet::static_for<0, CACHE_SIZE / SIMD_WIDTH>([&](auto I) { next().store_aligned(cache.data() + I * SIMD_WIDTH); });
  }

  // Generate `blocks` full CACHE_SIZE-value blocks straight to `out` (wide
  // unaligned stores, no cache bounce). Advances the state by blocks*CACHE_SIZE
  // outputs, exactly as that many populate_cache() calls would.
  SIMDRNG_ALWAYS_INLINE void generate_blocks(result_type *SIMDRNG_RESTRICT out, std::size_t blocks) noexcept {
    for (std::size_t b = 0; b < blocks; ++b) {
      result_type *SIMDRNG_RESTRICT dst = out + b * CACHE_SIZE;
      poet::static_for<0, CACHE_SIZE / SIMD_WIDTH>([&](auto I) { next().store_unaligned(dst + I * SIMD_WIDTH); });
    }
  }

  /**
   * Apply a jump polynomial to every lane: state <- poly(T) · state. All lanes
   * share the same polynomial (same jump count). Shared by every jump variant.
   */
  SIMDRNG_ALWAYS_INLINE constexpr void jump_poly(const result_type *SIMDRNG_RESTRICT poly) noexcept {
    static_assert(detail::jump_poly_t::size() == RNG_WIDTH, "jump polynomial word count must match the state width");
    simd_type s0(0);
    simd_type s1(0);
    simd_type s2(0);
    simd_type s3(0);
    for (std::uint8_t w = 0; w < RNG_WIDTH; ++w)
      for (auto b = 0; b < 64; b++) {
        if ((poly[w] & result_type{1} << b) != 0U) {
          s0 ^= s[0];
          s1 ^= s[1];
          s2 ^= s[2];
          s3 ^= s[3];
        }
        next();
      }
    s[0] = s0;
    s[1] = s1;
    s[2] = s2;
    s[3] = s3;
  }

  /**
   * Jump function. Equivalent to 2^128 calls to next().
   */
  SIMDRNG_ALWAYS_INLINE constexpr void jump() noexcept {
    constexpr result_type JUMP[] = {0x180ec6d33cfd0aba, 0xd5a61266f0c9392c, 0xa9582618e03fc9aa, 0x39abdc4529b1661c};
    jump_poly(JUMP);
  }

  /**
   * Mid-jump function. Equivalent to 2^160 calls to next().
   */
  SIMDRNG_ALWAYS_INLINE constexpr void mid_jump() noexcept {
    constexpr result_type MID_JUMP[] = {0xc04b4f9c5d26c200, 0x69e6e6e431a2d40b, 0x4823b45b89dc689c, 0xf567382197055bf0};
    jump_poly(MID_JUMP);
  }

  /**
   * Long-jump function. Equivalent to 2^192 calls to next().
   */
  SIMDRNG_ALWAYS_INLINE constexpr void long_jump() noexcept {
    constexpr result_type LONG_JUMP[] = {0x76e15d3efefdcbbf, 0xc5004e441c522fb3, 0x77710069854ee241,
                                         0x39109bb02acbe635};
    jump_poly(LONG_JUMP);
  }

  /**
   * Arbitrary jump-ahead: advances every lane by exactly n calls to next() via x^n mod P(x).
   * Overload of jump(); no-argument jump() remains the fixed 2^128 stride.
   */
  SIMDRNG_ALWAYS_INLINE constexpr void jump(std::uint64_t n) noexcept { jump_poly(detail::jump_poly_n(n).data()); }

  /**
   * Power-of-two jump-ahead: advances every lane by 2^p.exponent calls to next() via x^(2^e) mod P(x).
   */
  SIMDRNG_ALWAYS_INLINE constexpr void jump(pow2 p) noexcept { jump_poly(detail::jump_poly_pow2(p.exponent).data()); }

  SIMDRNG_ALWAYS_INLINE constexpr std::array<result_type, RNG_WIDTH> getState(const std::size_t index) const noexcept {
    std::array<result_type, RNG_WIDTH> state{};
    poet::static_for<0, RNG_WIDTH>([&](auto I) { state[I] = s[I].get(index); });
    return state;
  }

  void get_flat_state(result_type *out) const noexcept {
    for (std::uint8_t reg = 0; reg < RNG_WIDTH; ++reg)
      for (std::uint8_t lane = 0; lane < SIMD_WIDTH; ++lane)
        out[reg * SIMD_WIDTH + lane] = s[reg].get(lane);
  }

  void set_flat_state(const result_type *in) noexcept {
    for (std::uint8_t reg = 0; reg < RNG_WIDTH; ++reg) {
      std::array<result_type, SIMD_WIDTH> vals;
      for (std::uint8_t lane = 0; lane < SIMD_WIDTH; ++lane)
        vals[lane] = in[reg * SIMD_WIDTH + lane];
      s[reg] = simd_type::load_unaligned(vals.data());
    }
  }
};

/**
 * Result from the runtime dispatch initialization.
 */
struct XoshiroSIMDInitResult {
  using populate_fn = void (*)(void *SIMDRNG_RESTRICT, std::array<std::uint64_t, 256> &SIMDRNG_RESTRICT) noexcept;
  using generate_fn = void (*)(void *SIMDRNG_RESTRICT, std::uint64_t *SIMDRNG_RESTRICT, std::size_t) noexcept;
  using jump_fn = void (*)(void *) noexcept;
  using jump_n_fn = void (*)(void *, const std::uint64_t *) noexcept;
  using get_state_fn = void (*)(const void *, std::uint64_t *) noexcept;
  using set_state_fn = void (*)(void *, const std::uint64_t *) noexcept;
  using simd_width_fn = std::uint8_t (*)() noexcept;
  populate_fn populate_cache;
  generate_fn generate_blocks;
  jump_fn jump;
  jump_fn mid_jump;
  jump_fn long_jump;
  jump_n_fn jump_n;
  get_state_fn get_state;
  set_state_fn set_state;
  simd_width_fn simd_width;
};

/**
 * Functor used by xsimd::dispatch to initialize a XoshiroSIMD instance.
 * Placement-news the correct XoshiroState<Arch> into the byte storage and returns function pointers.
 */
struct XoshiroSIMDInitFunctor {
  void *state_storage;
  std::uint64_t seed;

  template <class Arch> XoshiroSIMDInitResult operator()(Arch /*arch*/) const noexcept;
};

template <class Arch> XoshiroSIMDInitResult XoshiroSIMDInitFunctor::operator()(Arch /*arch*/) const noexcept {
  using State = XoshiroState<Arch>;
  static_assert(sizeof(State) <= 256, "XoshiroState exceeds StateStorage capacity");
  static_assert(alignof(State) <= 64, "XoshiroState exceeds StateStorage alignment");
  auto *state = std::construct_at(static_cast<State *>(state_storage));
  state->seed(seed);
  return {
      +[](void *SIMDRNG_RESTRICT s, std::array<std::uint64_t, 256> &SIMDRNG_RESTRICT cache) noexcept {
        static_cast<State *>(s)->populate_cache(cache);
      },
      +[](void *SIMDRNG_RESTRICT s, std::uint64_t *SIMDRNG_RESTRICT out, std::size_t blocks) noexcept {
        static_cast<State *>(s)->generate_blocks(out, blocks);
      },
      +[](void *s) noexcept { static_cast<State *>(s)->jump(); },
      +[](void *s) noexcept { static_cast<State *>(s)->mid_jump(); },
      +[](void *s) noexcept { static_cast<State *>(s)->long_jump(); },
      +[](void *s, const std::uint64_t *poly) noexcept { static_cast<State *>(s)->jump_poly(poly); },
      +[](const void *s, std::uint64_t *out) noexcept { static_cast<const State *>(s)->get_flat_state(out); },
      +[](void *s, const std::uint64_t *in) noexcept { static_cast<State *>(s)->set_flat_state(in); },
      +[]() noexcept -> std::uint8_t { return State::SIMD_WIDTH; },
  };
}

#if SIMDRNG_ARCH_X86_64
extern template SIMDRNG_LOCAL
    XoshiroSIMDInitResult XoshiroSIMDInitFunctor::operator()<xsimd::sse2>(xsimd::sse2) const noexcept;
extern template SIMDRNG_LOCAL XoshiroSIMDInitResult
XoshiroSIMDInitFunctor::operator()<xsimd::avx2>(xsimd::avx2) const noexcept;
extern template SIMDRNG_LOCAL XoshiroSIMDInitResult
XoshiroSIMDInitFunctor::operator()<xsimd::avx512bw>(xsimd::avx512bw) const noexcept;
#elif SIMDRNG_ARCH_AARCH64
extern template SIMDRNG_LOCAL
    XoshiroSIMDInitResult XoshiroSIMDInitFunctor::operator()<xsimd::neon64>(xsimd::neon64) const noexcept;
#if XSIMD_WITH_SVE
extern template SIMDRNG_LOCAL
    XoshiroSIMDInitResult XoshiroSIMDInitFunctor::operator()<xsimd::sve>(xsimd::sve) const noexcept;
#endif
#elif SIMDRNG_ARCH_RISCV64
extern template SIMDRNG_LOCAL XoshiroSIMDInitResult
XoshiroSIMDInitFunctor::operator()<xsimd::detail::rvv<128>>(xsimd::detail::rvv<128>) const noexcept;
#endif

} // namespace internal

#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
/**
 * XoshiroNative: uses the best architecture available at compile time.
 * Zero indirection — direct calls to XoshiroState methods.
 */
class XoshiroNative {
  using State = internal::XoshiroState<xsimd::best_arch>;
  static constexpr auto CACHE_SIZE = State::CACHE_SIZE;

public:
  using result_type = std::uint64_t;
  static constexpr SIMDRNG_ALWAYS_INLINE auto(min)() noexcept { return (std::numeric_limits<result_type>::min)(); }
  static constexpr SIMDRNG_ALWAYS_INLINE auto(max)() noexcept { return (std::numeric_limits<result_type>::max)(); }
  static constexpr SIMDRNG_ALWAYS_INLINE auto stateSize() noexcept { return State::RNG_WIDTH; }

  SIMDRNG_ALWAYS_INLINE explicit XoshiroNative(const result_type seed) noexcept { m_state.seed(seed); }

  SIMDRNG_ALWAYS_INLINE result_type operator()() noexcept {
    if (m_index == 0) [[unlikely]] {
      m_state.populate_cache(m_cache);
    }
    return m_cache[m_index++];
  }

  SIMDRNG_ALWAYS_INLINE double uniform() noexcept { return static_cast<double>(operator()() >> 11) * 0x1.0p-53; }

  // Bulk fill, bit-identical to n consecutive operator() calls (see XoshiroSIMD).
  void generate(result_type *SIMDRNG_RESTRICT out, std::size_t n) noexcept {
    std::size_t produced = 0;
    std::uint8_t idx = m_index;
    if (idx != 0) {
      const std::size_t avail = CACHE_SIZE - idx;
      const std::size_t take = avail < n ? avail : n;
      std::memcpy(out, m_cache.data() + idx, take * sizeof(result_type));
      idx = static_cast<std::uint8_t>(idx + take);
      produced = take;
    }
    const std::size_t mid_blocks = (n - produced) / CACHE_SIZE;
    if (mid_blocks != 0) {
      m_state.generate_blocks(out + produced, mid_blocks);
      produced += mid_blocks * CACHE_SIZE;
    }
    if (produced < n) {
      m_state.populate_cache(m_cache);
      const std::size_t rem = n - produced;
      std::memcpy(out + produced, m_cache.data(), rem * sizeof(result_type));
      idx = static_cast<std::uint8_t>(rem);
    }
    m_index = idx;
  }

  void fill_uniform(double *SIMDRNG_RESTRICT out, std::size_t n) noexcept {
    alignas(64) std::array<result_type, CACHE_SIZE> buf;
    std::size_t done = 0;
    while (done < n) {
      const std::size_t take = (n - done) < CACHE_SIZE ? (n - done) : CACHE_SIZE;
      generate(buf.data(), take);
      for (std::size_t i = 0; i < take; ++i)
        out[done + i] = static_cast<double>(buf[i] >> 11) * 0x1.0p-53;
      done += take;
    }
  }

  SIMDRNG_ALWAYS_INLINE auto getState(const std::size_t index) const noexcept { return m_state.getState(index); }

  SIMDRNG_ALWAYS_INLINE void jump() noexcept { m_state.jump(); }
  SIMDRNG_ALWAYS_INLINE void mid_jump() noexcept { m_state.mid_jump(); }
  SIMDRNG_ALWAYS_INLINE void long_jump() noexcept { m_state.long_jump(); }
  SIMDRNG_ALWAYS_INLINE void jump(result_type n) noexcept { m_state.jump(n); }
  SIMDRNG_ALWAYS_INLINE void jump(pow2 p) noexcept { m_state.jump(p); }

  void get_flat_state(result_type *out) const noexcept { m_state.get_flat_state(out); }
  void set_flat_state(const result_type *in) noexcept { m_state.set_flat_state(in); }
  static constexpr std::uint8_t simd_width() noexcept { return State::SIMD_WIDTH; }

  std::uint8_t cache_index() const noexcept { return m_index; }
  void set_cache_index(std::uint8_t idx) noexcept { m_index = idx; }
  const std::array<result_type, CACHE_SIZE> &cache() const noexcept { return m_cache; }
  std::array<result_type, CACHE_SIZE> &cache() noexcept { return m_cache; }

private:
  alignas(State::simd_type::arch_type::alignment()) std::array<result_type, CACHE_SIZE> m_cache{};
  State m_state{};
  std::uint8_t m_index{0};
};
#endif // XSIMD_NO_SUPPORTED_ARCHITECTURE

/**
 * XoshiroSIMD: runtime SIMD dispatch via inline union + function pointers.
 * No heap allocation, no virtual dispatch.
 */
class XoshiroSIMD {
public:
  using result_type = std::uint64_t;
  static constexpr SIMDRNG_ALWAYS_INLINE result_type(min)() noexcept {
    return (std::numeric_limits<result_type>::min)();
  }
  static constexpr SIMDRNG_ALWAYS_INLINE result_type(max)() noexcept {
    return (std::numeric_limits<result_type>::max)();
  }

  SIMDRNG_LOCAL explicit XoshiroSIMD(result_type seed) noexcept;

  SIMDRNG_ALWAYS_INLINE result_type operator()() noexcept {
    if (m_index == 0) [[unlikely]] {
      m_populate_cache(m_state.data, m_cache);
    }
    return m_cache[m_index++];
  }

  SIMDRNG_ALWAYS_INLINE double uniform() noexcept { return static_cast<double>(operator()() >> 11) * 0x1.0p-53; }

  // Bulk fill: bit-identical to n consecutive operator() calls. Drains the
  // partial cache prefix, generates the aligned middle with wide stores
  // straight to `out` via a single dispatched call, then refills the cache for
  // the < CACHE_SIZE tail and parks the cursor so the next operator() resumes
  // the exact stream.
  void generate(result_type *SIMDRNG_RESTRICT out, std::size_t n) noexcept {
    std::size_t produced = 0;
    std::uint8_t idx = m_index;
    if (idx != 0) {
      const std::size_t avail = CACHE_SIZE - idx;
      const std::size_t take = avail < n ? avail : n;
      std::memcpy(out, m_cache.data() + idx, take * sizeof(result_type));
      idx = static_cast<std::uint8_t>(idx + take);
      produced = take;
    }
    const std::size_t mid_blocks = (n - produced) / CACHE_SIZE;
    if (mid_blocks != 0) {
      m_generate(m_state.data, out + produced, mid_blocks);
      produced += mid_blocks * CACHE_SIZE;
    }
    if (produced < n) {
      m_populate_cache(m_state.data, m_cache);
      const std::size_t rem = n - produced;
      std::memcpy(out + produced, m_cache.data(), rem * sizeof(result_type));
      idx = static_cast<std::uint8_t>(rem);
    }
    m_index = idx;
  }

  void fill_uniform(double *SIMDRNG_RESTRICT out, std::size_t n) noexcept {
    alignas(64) std::array<result_type, CACHE_SIZE> buf;
    std::size_t done = 0;
    while (done < n) {
      const std::size_t take = (n - done) < CACHE_SIZE ? (n - done) : CACHE_SIZE;
      generate(buf.data(), take);
      for (std::size_t i = 0; i < take; ++i)
        out[done + i] = static_cast<double>(buf[i] >> 11) * 0x1.0p-53;
      done += take;
    }
  }

  SIMDRNG_ALWAYS_INLINE void jump() noexcept { m_jump(m_state.data); }
  SIMDRNG_ALWAYS_INLINE void mid_jump() noexcept { m_mid_jump(m_state.data); }
  SIMDRNG_ALWAYS_INLINE void long_jump() noexcept { m_long_jump(m_state.data); }

  // Arbitrary jump-ahead. The jump polynomial x^n mod P(x) is arch-independent
  // (pure scalar math), so it is computed once here and applied to every lane.
  SIMDRNG_ALWAYS_INLINE void jump(result_type n) noexcept { m_jump_n(m_state.data, detail::jump_poly_n(n).data()); }

  // Power-of-two jump-ahead: 2^p.exponent steps. Same arch-independent poly path.
  SIMDRNG_ALWAYS_INLINE void jump(pow2 p) noexcept {
    m_jump_n(m_state.data, detail::jump_poly_pow2(p.exponent).data());
  }

  void get_flat_state(result_type *out) const noexcept { m_get_state(m_state.data, out); }
  void set_flat_state(const result_type *in) noexcept { m_set_state(m_state.data, in); }
  std::uint8_t simd_width() const noexcept { return m_simd_width(); }

  std::uint8_t cache_index() const noexcept { return m_index; }
  void set_cache_index(std::uint8_t idx) noexcept { m_index = idx; }
  const std::array<result_type, std::numeric_limits<std::uint8_t>::max() + 1> &cache() const noexcept {
    return m_cache;
  }
  std::array<result_type, std::numeric_limits<std::uint8_t>::max() + 1> &cache() noexcept { return m_cache; }

protected:
  static constexpr std::uint16_t CACHE_SIZE = std::numeric_limits<std::uint8_t>::max() + 1;
  using populate_fn = void (*)(void *SIMDRNG_RESTRICT, std::array<result_type, CACHE_SIZE> &SIMDRNG_RESTRICT) noexcept;
  using generate_fn = void (*)(void *SIMDRNG_RESTRICT, result_type *SIMDRNG_RESTRICT, std::size_t) noexcept;
  using jump_fn = void (*)(void *) noexcept;
  using jump_n_fn = void (*)(void *, const result_type *) noexcept;
  using get_state_fn = void (*)(const void *, result_type *) noexcept;
  using set_state_fn = void (*)(void *, const result_type *) noexcept;
  using simd_width_fn = std::uint8_t (*)() noexcept;

  // Raw byte storage for the arch-specific XoshiroState.
  // Typed union is not viable: xsimd batch types have different sizeof
  // across TUs compiled with different -march flags (ODR divergence).
  // Max is avx512bw: 4 × sizeof(__m512i) = 4 × 64 = 256 bytes, align 64.
  struct StateStorage {
    static constexpr std::size_t SIZE = 256;
    static constexpr std::size_t ALIGN = 64;
    alignas(ALIGN) unsigned char data[SIZE];
  };

  alignas(64) std::array<result_type, CACHE_SIZE> m_cache{};
  alignas(64) StateStorage m_state{};
  populate_fn m_populate_cache = nullptr;
  generate_fn m_generate = nullptr;
  jump_fn m_jump = nullptr;
  jump_fn m_mid_jump = nullptr;
  jump_fn m_long_jump = nullptr;
  jump_n_fn m_jump_n = nullptr;
  get_state_fn m_get_state = nullptr;
  set_state_fn m_set_state = nullptr;
  simd_width_fn m_simd_width = nullptr;
  std::uint8_t m_index{0};
};

} // namespace simdrng
