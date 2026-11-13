#include <cstring>
#include <nanobind/nanobind.h>
#include <nanobind/ndarray.h>
#include <nanobind/stl/array.h>
#include <nanobind/stl/vector.h>
#include <numpy/random/bitgen.h>
#include <type_traits>

#include <poet/poet.hpp>

#include "simdrng/chacha_simd.hpp"
#include "simdrng/macros.hpp"
#include "simdrng/philox_simd.hpp"
#include "simdrng/splitmix.hpp"
#include "simdrng/stream_levels.hpp"
#include "simdrng/xoshiro_scalar.hpp"
#include "simdrng/xoshiro_simd.hpp"

namespace nb = nanobind;
using namespace nb::literals;

namespace {
constexpr double kInvPow53 = 0x1.0p-53;

// Validates a Python stream-level value against the C++ width table.
// Raises ValueError for non-integers, negatives, or values past the field
// width (or past 2^64-1), so bad input never reaches the C++ abort.
std::uint64_t checked_level(const char *level, std::uint64_t bits, nb::object value) {
  const nb::handle h = value;
  if (!nb::isinstance<nb::int_>(h))
    throw nb::value_error((std::string(level) + " must be an integer").c_str());
  const std::uint64_t field_max = bits < 64 ? (std::uint64_t{1} << bits) - 1 : (std::uint64_t)-1;
  {
    const nb::handle zero(PyLong_FromLong(0));
    if (PyObject_RichCompareBool(h.ptr(), zero.ptr(), Py_LT) == 1)
      throw nb::value_error((std::string(level) + " must be non-negative").c_str());
  }
  {
    const nb::handle maxv(PyLong_FromUnsignedLongLong(field_max));
    if (PyObject_RichCompareBool(h.ptr(), maxv.ptr(), Py_GT) == 1)
      throw nb::value_error((std::string(level) + " must fit in " + std::to_string(bits) + " bits").c_str());
  }
  const nb::int_ v = nb::borrow<nb::int_>(h);
  return (std::uint64_t)v;
}

// Constructs the wrapper with the None rule: all three level keywords None
// uses the plain constructor and the plain lane layout. Any level keyword
// calls the C++ tag API with the missing levels at 0. The level values are
// checked against the C++ width table first.
template <typename Rng, typename Py>
void init_leveled(Py *self, std::uint64_t seed, nb::object node, nb::object gpu, nb::object thread) {
  if (node.is_none() && gpu.is_none() && thread.is_none()) {
    new (self) Py(seed);
    return;
  }
  const auto W = simdrng::detail::widths_xoshiro256;
  const nb::object zero = nb::int_(0);
  const std::uint64_t n = checked_level("node", W.node_bits, node.is_none() ? zero : node);
  const std::uint64_t g = checked_level("gpu", W.gpu_bits, gpu.is_none() ? zero : gpu);
  const std::uint64_t t = checked_level("thread", W.thread_bits, thread.is_none() ? zero : thread);
  new (self) Py(seed, simdrng::node{n}, simdrng::gpu{g}, simdrng::thread{t});
}

// ---------------------------------------------------------------------------
// Type traits for dispatch in bulk fill and state serialization
template <typename T> struct is_xoshiro_cached : std::false_type {};
template <> struct is_xoshiro_cached<simdrng::XoshiroSIMD> : std::true_type {};
#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
template <> struct is_xoshiro_cached<simdrng::XoshiroNative> : std::true_type {};
#endif

template <typename T> struct is_chacha : std::false_type {};
template <std::uint8_t R> struct is_chacha<simdrng::ChaChaSIMD<R>> : std::true_type {};
#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
template <std::uint8_t R> struct is_chacha<simdrng::ChaChaNative<R>> : std::true_type {};
#endif

template <typename T> struct is_philox : std::false_type {};
template <std::uint8_t N, std::uint8_t W, std::uint8_t R>
struct is_philox<simdrng::PhiloxSIMD<N, W, R>> : std::true_type {};
#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
template <std::uint8_t N, std::uint8_t W, std::uint8_t R>
struct is_philox<simdrng::PhiloxNative<N, W, R>> : std::true_type {};
#endif

// True for generators exposing the dispatched bulk-fill API
// (generate(uint64*, n) / fill_uniform(double*, n)) — every SIMD/Native
// generator. Scalar generators fall back to the per-sample loop.
template <typename T, typename = void> struct has_bulk_fill : std::false_type {};
template <typename T>
struct has_bulk_fill<
    T, std::void_t<decltype(std::declval<T &>().generate(std::declval<std::uint64_t *>(), std::size_t{}))>>
    : std::true_type {};

// ---------------------------------------------------------------------------
// PyBitGenerator<Rng>: single template replacing DirectBitGen + per-gen wrappers.
// Contains: Rng instance + bitgen_t (stable address, no heap indirection).
// No dcache — generators use their own internal caches.
template <typename Rng> struct PyBitGenerator {
  Rng rng;
  bitgen_t bitgen;

  template <typename... Args> explicit PyBitGenerator(Args &&...args) : rng(std::forward<Args>(args)...), bitgen{} {
    bitgen.state = this;
    bitgen.next_uint64 = &next_u64;
    bitgen.next_uint32 = &next_u32;
    bitgen.next_double = &next_f64;
    bitgen.next_raw = &next_u64;
  }

  // Static callbacks — called by NumPy's Generator per-sample.
  // No virtual dispatch, no lambda thunks.
  static uint64_t next_u64(void *s) noexcept { return static_cast<PyBitGenerator *>(s)->rng(); }
  static uint32_t next_u32(void *s) noexcept {
    return static_cast<uint32_t>(static_cast<PyBitGenerator *>(s)->rng() >> 32);
  }
  static double next_f64(void *s) noexcept {
    return static_cast<double>(static_cast<PyBitGenerator *>(s)->rng() >> 11) * kInvPow53;
  }

  // Non-owning capsule — Python wrapper prevents GC via reference.
  nb::object capsule() { return nb::steal(PyCapsule_New(&bitgen, "BitGenerator", nullptr)); }

  uint64_t random_raw() noexcept { return rng(); }

  // -- Bulk fill: float64 --------------------------------------------------
  void fill_uniform(nb::ndarray<nb::numpy, double, nb::ndim<1>, nb::c_contig> out) noexcept {
    nb::gil_scoped_release release;
    auto *data = out.data();
    const std::size_t n = out.size();
    if constexpr (has_bulk_fill<Rng>::value) {
      rng.fill_uniform(data, n);
    } else {
      for (std::size_t i = 0; i < n; ++i)
        data[i] = static_cast<double>(rng() >> 11) * kInvPow53;
    }
  }

  // -- Bulk fill: uint64 ---------------------------------------------------
  void fill_uint64(nb::ndarray<nb::numpy, uint64_t, nb::ndim<1>, nb::c_contig> out) noexcept {
    nb::gil_scoped_release release;
    auto *data = out.data();
    const std::size_t n = out.size();
    if constexpr (has_bulk_fill<Rng>::value) {
      rng.generate(data, n);
    } else {
      for (std::size_t i = 0; i < n; ++i)
        data[i] = rng();
    }
  }

  // -- Bulk fill: float32 (2 samples per uint64) ---------------------------
  void fill_float32(nb::ndarray<nb::numpy, float, nb::ndim<1>, nb::c_contig> out) noexcept {
    nb::gil_scoped_release release;
    auto *data = out.data();
    const std::size_t n = out.size();
    constexpr float kScale = 1.0f / 16777216.0f; // 2^-24
    if constexpr (has_bulk_fill<Rng>::value) {
      // Generate the raw uint64 stream in chunks, then split 2 float32 each.
      constexpr std::size_t kChunk = 256;
      alignas(64) std::uint64_t buf[kChunk];
      std::size_t pos = 0;
      while (pos < n) {
        const std::size_t need = (n - pos + 1) / 2;
        const std::size_t take = need < kChunk ? need : kChunk;
        rng.generate(buf, take);
        for (std::size_t j = 0; j < take; ++j)
          data_from_u64_f32(data, pos, n, buf[j], kScale);
      }
    } else {
      std::size_t i = 0;
      for (; i + 1 < n; i += 2) {
        uint64_t raw = rng();
        data[i] = static_cast<float>(static_cast<uint32_t>(raw >> 32) >> 8) * kScale;
        data[i + 1] = static_cast<float>(static_cast<uint32_t>(raw) >> 8) * kScale;
      }
      if (i < n)
        data[i] = static_cast<float>(static_cast<uint32_t>(rng() >> 32) >> 8) * kScale;
    }
  }

  // -- Bulk fill: uint32 (2 samples per uint64) ----------------------------
  void fill_uint32(nb::ndarray<nb::numpy, uint32_t, nb::ndim<1>, nb::c_contig> out) noexcept {
    nb::gil_scoped_release release;
    auto *data = out.data();
    const std::size_t n = out.size();
    if constexpr (has_bulk_fill<Rng>::value) {
      constexpr std::size_t kChunk = 256;
      alignas(64) std::uint64_t buf[kChunk];
      std::size_t pos = 0;
      while (pos < n) {
        const std::size_t need = (n - pos + 1) / 2;
        const std::size_t take = need < kChunk ? need : kChunk;
        rng.generate(buf, take);
        for (std::size_t j = 0; j < take; ++j)
          data_from_u64_u32(data, pos, n, buf[j]);
      }
    } else {
      std::size_t i = 0;
      for (; i + 1 < n; i += 2) {
        uint64_t raw = rng();
        data[i] = static_cast<uint32_t>(raw >> 32);
        data[i + 1] = static_cast<uint32_t>(raw);
      }
      if (i < n)
        data[i] = static_cast<uint32_t>(rng() >> 32);
    }
  }

  // -- State serialization -------------------------------------------------
  nb::dict get_state() const;
  void set_state(nb::dict d);

private:
  static void data_from_u64_f32(float *out, std::size_t &pos, std::size_t n, uint64_t raw, float scale) noexcept {
    out[pos++] = static_cast<float>(static_cast<uint32_t>(raw >> 32) >> 8) * scale;
    if (pos < n)
      out[pos++] = static_cast<float>(static_cast<uint32_t>(raw) >> 8) * scale;
  }

  static void data_from_u64_u32(uint32_t *out, std::size_t &pos, std::size_t n, uint64_t raw) noexcept {
    out[pos++] = static_cast<uint32_t>(raw >> 32);
    if (pos < n)
      out[pos++] = static_cast<uint32_t>(raw);
  }
};

// ---------------------------------------------------------------------------
// State serialization: SplitMix
template <> nb::dict PyBitGenerator<simdrng::SplitMix>::get_state() const {
  nb::dict d;
  d["s"] = rng.getState();
  return d;
}
template <> void PyBitGenerator<simdrng::SplitMix>::set_state(nb::dict d) { rng.setState(nb::cast<uint64_t>(d["s"])); }

// ---------------------------------------------------------------------------
// State serialization: XoshiroScalar
template <> nb::dict PyBitGenerator<simdrng::XoshiroScalar>::get_state() const {
  auto s = rng.getState();
  nb::dict d;
  d["s"] = std::vector<uint64_t>(s.begin(), s.end());
  return d;
}
template <> void PyBitGenerator<simdrng::XoshiroScalar>::set_state(nb::dict d) {
  auto v = nb::cast<std::vector<uint64_t>>(d["s"]);
  std::array<uint64_t, 4> s;
  for (int i = 0; i < 4; ++i)
    s[i] = v[i];
  rng.setState(s);
}

// ---------------------------------------------------------------------------
// State serialization helper for Xoshiro SIMD/Native
template <typename Rng> nb::dict get_xoshiro_cached_state(const Rng &rng) {
  const auto sw = rng.simd_width();
  const std::size_t state_len = 4 * sw;
  std::vector<uint64_t> flat(state_len);
  rng.get_flat_state(flat.data());
  const auto &cache = rng.cache();
  std::vector<uint64_t> cache_vec(cache.begin(), cache.end());
  nb::dict d;
  d["s"] = std::move(flat);
  d["cache"] = std::move(cache_vec);
  d["cache_index"] = rng.cache_index();
  d["simd_width"] = sw;
  return d;
}

template <typename Rng> void set_xoshiro_cached_state(Rng &rng, nb::dict d) {
  auto flat = nb::cast<std::vector<uint64_t>>(d["s"]);
  rng.set_flat_state(flat.data());
  auto cache_vec = nb::cast<std::vector<uint64_t>>(d["cache"]);
  auto &cache = rng.cache();
  for (std::size_t i = 0; i < 256 && i < cache_vec.size(); ++i)
    cache[i] = cache_vec[i];
  rng.set_cache_index(nb::cast<uint8_t>(d["cache_index"]));
}

// XoshiroSIMD
template <> nb::dict PyBitGenerator<simdrng::XoshiroSIMD>::get_state() const { return get_xoshiro_cached_state(rng); }
template <> void PyBitGenerator<simdrng::XoshiroSIMD>::set_state(nb::dict d) { set_xoshiro_cached_state(rng, d); }

// XoshiroNative
#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
template <> nb::dict PyBitGenerator<simdrng::XoshiroNative>::get_state() const { return get_xoshiro_cached_state(rng); }
template <> void PyBitGenerator<simdrng::XoshiroNative>::set_state(nb::dict d) { set_xoshiro_cached_state(rng, d); }
#endif

// ---------------------------------------------------------------------------
// State serialization helper for ChaCha SIMD/Native
template <typename Rng> nb::dict get_chacha_state(const Rng &rng) {
  auto matrix = rng.getStateForSerde();
  auto rc = rng.result_cache();
  nb::dict d;
  d["matrix"] = std::vector<uint32_t>(matrix.begin(), matrix.end());
  d["result_cache"] = std::vector<uint64_t>(rc.begin(), rc.end());
  d["result_index"] = rng.result_index();
  return d;
}

template <typename Rng> void set_chacha_state(Rng &rng, nb::dict d) {
  auto mv = nb::cast<std::vector<uint32_t>>(d["matrix"]);
  std::array<uint32_t, 16> matrix;
  for (int i = 0; i < 16; ++i)
    matrix[i] = mv[i];
  rng.setState(matrix);
  auto rcv = nb::cast<std::vector<uint64_t>>(d["result_cache"]);
  typename Rng::result_cache_type rc;
  for (std::size_t i = 0; i < rc.size() && i < rcv.size(); ++i)
    rc[i] = rcv[i];
  rng.set_result_cache(rc);
  rng.set_result_index(nb::cast<uint8_t>(d["result_index"]));
}

// ChaChaSIMD<8>, <12>, <20>
template <> nb::dict PyBitGenerator<simdrng::ChaChaSIMD<8>>::get_state() const { return get_chacha_state(rng); }
template <> void PyBitGenerator<simdrng::ChaChaSIMD<8>>::set_state(nb::dict d) { set_chacha_state(rng, d); }
template <> nb::dict PyBitGenerator<simdrng::ChaChaSIMD<12>>::get_state() const { return get_chacha_state(rng); }
template <> void PyBitGenerator<simdrng::ChaChaSIMD<12>>::set_state(nb::dict d) { set_chacha_state(rng, d); }
template <> nb::dict PyBitGenerator<simdrng::ChaChaSIMD<20>>::get_state() const { return get_chacha_state(rng); }
template <> void PyBitGenerator<simdrng::ChaChaSIMD<20>>::set_state(nb::dict d) { set_chacha_state(rng, d); }

// ChaChaNative<8>, <12>, <20>
#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
template <> nb::dict PyBitGenerator<simdrng::ChaChaNative<8>>::get_state() const { return get_chacha_state(rng); }
template <> void PyBitGenerator<simdrng::ChaChaNative<8>>::set_state(nb::dict d) { set_chacha_state(rng, d); }
template <> nb::dict PyBitGenerator<simdrng::ChaChaNative<12>>::get_state() const { return get_chacha_state(rng); }
template <> void PyBitGenerator<simdrng::ChaChaNative<12>>::set_state(nb::dict d) { set_chacha_state(rng, d); }
template <> nb::dict PyBitGenerator<simdrng::ChaChaNative<20>>::get_state() const { return get_chacha_state(rng); }
template <> void PyBitGenerator<simdrng::ChaChaNative<20>>::set_state(nb::dict d) { set_chacha_state(rng, d); }
#endif

// ---------------------------------------------------------------------------
// State serialization helper for Philox SIMD/Native
template <typename Rng> nb::dict get_philox_state(const Rng &rng) {
  using word_type = typename Rng::word_type;
  auto ctr = rng.getCounterForSerde();
  auto key = rng.getKey();
  const auto &cache = rng.cache();
  nb::dict d;
  d["counter"] = std::vector<word_type>(ctr.begin(), ctr.end());
  d["key"] = std::vector<word_type>(key.begin(), key.end());
  d["cache"] = std::vector<uint64_t>(cache.begin(), cache.end());
  d["cache_index"] = rng.cache_index();
  return d;
}

template <typename Rng> void set_philox_state(Rng &rng, nb::dict d) {
  using word_type = typename Rng::word_type;
  auto cv = nb::cast<std::vector<word_type>>(d["counter"]);
  auto kv = nb::cast<std::vector<word_type>>(d["key"]);
  typename Rng::counter_type ctr;
  typename Rng::key_type key;
  for (std::size_t i = 0; i < ctr.size() && i < cv.size(); ++i)
    ctr[i] = cv[i];
  for (std::size_t i = 0; i < key.size() && i < kv.size(); ++i)
    key[i] = kv[i];
  rng.setState(ctr, key);
  auto cache_vec = nb::cast<std::vector<uint64_t>>(d["cache"]);
  auto &cache = rng.cache();
  for (std::size_t i = 0; i < cache.size() && i < cache_vec.size(); ++i)
    cache[i] = cache_vec[i];
  rng.set_cache_index(nb::cast<uint8_t>(d["cache_index"]));
}

// Philox SIMD state specializations for all four NxW combos
using Philox4x32SIMD_t = simdrng::PhiloxSIMD<4, 32, 10>;
using Philox2x32SIMD_t = simdrng::PhiloxSIMD<2, 32, 10>;
using Philox4x64SIMD_t = simdrng::PhiloxSIMD<4, 64, 10>;
using Philox2x64SIMD_t = simdrng::PhiloxSIMD<2, 64, 10>;

template <> nb::dict PyBitGenerator<Philox4x32SIMD_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox4x32SIMD_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
template <> nb::dict PyBitGenerator<Philox2x32SIMD_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox2x32SIMD_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
template <> nb::dict PyBitGenerator<Philox4x64SIMD_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox4x64SIMD_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
template <> nb::dict PyBitGenerator<Philox2x64SIMD_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox2x64SIMD_t>::set_state(nb::dict d) { set_philox_state(rng, d); }

#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
using Philox4x32Native_t = simdrng::PhiloxNative<4, 32, 10>;
using Philox2x32Native_t = simdrng::PhiloxNative<2, 32, 10>;
using Philox4x64Native_t = simdrng::PhiloxNative<4, 64, 10>;
using Philox2x64Native_t = simdrng::PhiloxNative<2, 64, 10>;

template <> nb::dict PyBitGenerator<Philox4x32Native_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox4x32Native_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
template <> nb::dict PyBitGenerator<Philox2x32Native_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox2x32Native_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
template <> nb::dict PyBitGenerator<Philox4x64Native_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox4x64Native_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
template <> nb::dict PyBitGenerator<Philox2x64Native_t>::get_state() const { return get_philox_state(rng); }
template <> void PyBitGenerator<Philox2x64Native_t>::set_state(nb::dict d) { set_philox_state(rng, d); }
#endif

// ---------------------------------------------------------------------------
// Registration helpers to reduce boilerplate.

// Base registration: capsule, random_raw, state, fill methods.
template <typename Rng, typename Class> void register_base(Class &cls) {
  cls.def("capsule", &PyBitGenerator<Rng>::capsule)
      .def("random_raw", &PyBitGenerator<Rng>::random_raw)
      .def("get_state", &PyBitGenerator<Rng>::get_state)
      .def("set_state", &PyBitGenerator<Rng>::set_state, "state"_a)
      .def("fill_uniform", &PyBitGenerator<Rng>::fill_uniform, "out"_a)
      .def("fill_float32", &PyBitGenerator<Rng>::fill_float32, "out"_a)
      .def("fill_uint64", &PyBitGenerator<Rng>::fill_uint64, "out"_a)
      .def("fill_uint32", &PyBitGenerator<Rng>::fill_uint32, "out"_a);
}

// Jump registration for Xoshiro family.
template <typename Rng> struct has_jump : std::false_type {};
template <> struct has_jump<simdrng::XoshiroScalar> : std::true_type {};
template <> struct has_jump<simdrng::XoshiroSIMD> : std::true_type {};
#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
template <> struct has_jump<simdrng::XoshiroNative> : std::true_type {};
#endif

template <typename Rng, typename Class> void register_jump(Class &cls) {
  if constexpr (has_jump<Rng>::value) {
    cls.def("jump", [](PyBitGenerator<Rng> &self) { self.rng.jump(); })
        .def("long_jump", [](PyBitGenerator<Rng> &self) { self.rng.long_jump(); })
        .def(
            "jump", [](PyBitGenerator<Rng> &self, std::uint64_t n) { self.rng.jump(n); }, "n"_a)
        .def("jump", [](PyBitGenerator<Rng> &self, simdrng::pow2 p) { self.rng.jump(p); }, "exp"_a);
  }
}

} // anonymous namespace

// ---------------------------------------------------------------------------
// Python module
NB_MODULE(simdrng_ext, m) {
  // Power-of-two jump tag: bg.jump(pow2(128)) advances by 2^128.
  nb::class_<simdrng::pow2>(m, "pow2")
      .def(nb::init<std::uint64_t>(), "exponent"_a)
      .def_rw("exponent", &simdrng::pow2::exponent);

  using PySplitMix = PyBitGenerator<simdrng::SplitMix>;
  auto sm = nb::class_<PySplitMix>(m, "_SplitMix").def(nb::init<uint64_t>(), "seed"_a);
  register_base<simdrng::SplitMix>(sm);

  using PyXoshiro = PyBitGenerator<simdrng::XoshiroScalar>;
  auto xo = nb::class_<PyXoshiro>(m, "_Xoshiro")
                .def(nb::init<uint64_t>(), "seed"_a)
                // Hierarchical stream levels, any subset in any order. All the
                // level keywords None keeps the plain constructor; any level
                // keyword given calls the tag API with the missing levels at 0.
                .def(
                    "__init__",
                    [](PyXoshiro *self, std::uint64_t seed, nb::object node = nb::none(), nb::object gpu = nb::none(),
                       nb::object thread = nb::none()) {
                      init_leveled<simdrng::XoshiroScalar>(self, seed, node, gpu, thread);
                    },
                    "seed"_a, "node"_a, "gpu"_a, "thread"_a);
  register_base<simdrng::XoshiroScalar>(xo);
  register_jump<simdrng::XoshiroScalar>(xo);

  using PyXoshiroSIMD = PyBitGenerator<simdrng::XoshiroSIMD>;
  auto xs =
      nb::class_<PyXoshiroSIMD>(m, "_XoshiroSIMD")
          .def(nb::init<uint64_t>(), "seed"_a)
          // Same tag API as the scalar class. The tagged lanes split the
          // 2^127 block of the level tuple; see the readme for the lane
          // layout and the plain-seed caveat.
          .def(
              "__init__",
              [](PyXoshiroSIMD *self, std::uint64_t seed, nb::object node = nb::none(), nb::object gpu = nb::none(),
                 nb::object thread = nb::none()) { init_leveled<simdrng::XoshiroSIMD>(self, seed, node, gpu, thread); },
              "seed"_a, "node"_a, "gpu"_a, "thread"_a);
  register_base<simdrng::XoshiroSIMD>(xs);
  register_jump<simdrng::XoshiroSIMD>(xs);

#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
  using PyXoshiroNative = PyBitGenerator<simdrng::XoshiroNative>;
  auto xn = nb::class_<PyXoshiroNative>(m, "_XoshiroNative")
                .def(nb::init<uint64_t>(), "seed"_a)
                // Same tag API and lane layout as _XoshiroSIMD.
                .def(
                    "__init__",
                    [](PyXoshiroNative *self, std::uint64_t seed, nb::object node = nb::none(),
                       nb::object gpu = nb::none(), nb::object thread = nb::none()) {
                      init_leveled<simdrng::XoshiroNative>(self, seed, node, gpu, thread);
                    },
                    "seed"_a, "node"_a, "gpu"_a, "thread"_a);
  register_base<simdrng::XoshiroNative>(xn);
  register_jump<simdrng::XoshiroNative>(xn);
#endif

  // ChaCha SIMD variants — accept both (seed) and (key, counter, nonce)
  using key_t = std::array<uint32_t, 8>;

  using PyChaCha8SIMD = PyBitGenerator<simdrng::ChaChaSIMD<8>>;
  auto c8s = nb::class_<PyChaCha8SIMD>(m, "_ChaCha8SIMD")
                 .def(nb::init<uint64_t>(), "seed"_a)
                 .def(nb::init<uint64_t, uint64_t, uint64_t>(), "seed"_a, "counter"_a, "nonce"_a)
                 .def(nb::init<key_t, uint64_t, uint64_t>(), "key"_a, "counter"_a, "nonce"_a);
  register_base<simdrng::ChaChaSIMD<8>>(c8s);

  using PyChaCha12SIMD = PyBitGenerator<simdrng::ChaChaSIMD<12>>;
  auto c12s = nb::class_<PyChaCha12SIMD>(m, "_ChaCha12SIMD")
                  .def(nb::init<uint64_t>(), "seed"_a)
                  .def(nb::init<uint64_t, uint64_t, uint64_t>(), "seed"_a, "counter"_a, "nonce"_a)
                  .def(nb::init<key_t, uint64_t, uint64_t>(), "key"_a, "counter"_a, "nonce"_a);
  register_base<simdrng::ChaChaSIMD<12>>(c12s);

  using PyChaCha20SIMD = PyBitGenerator<simdrng::ChaChaSIMD<20>>;
  auto c20s = nb::class_<PyChaCha20SIMD>(m, "_ChaCha20SIMD")
                  .def(nb::init<uint64_t>(), "seed"_a)
                  .def(nb::init<uint64_t, uint64_t, uint64_t>(), "seed"_a, "counter"_a, "nonce"_a)
                  .def(nb::init<key_t, uint64_t, uint64_t>(), "key"_a, "counter"_a, "nonce"_a);
  register_base<simdrng::ChaChaSIMD<20>>(c20s);

#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
  // ChaCha Native variants — accept both (seed) and (key, counter, nonce)
  using PyChaCha8Native = PyBitGenerator<simdrng::ChaChaNative<8>>;
  auto c8n = nb::class_<PyChaCha8Native>(m, "_ChaCha8Native")
                 .def(nb::init<uint64_t>(), "seed"_a)
                 .def(nb::init<uint64_t, uint64_t, uint64_t>(), "seed"_a, "counter"_a, "nonce"_a)
                 .def(nb::init<key_t, uint64_t, uint64_t>(), "key"_a, "counter"_a, "nonce"_a);
  register_base<simdrng::ChaChaNative<8>>(c8n);

  using PyChaCha12Native = PyBitGenerator<simdrng::ChaChaNative<12>>;
  auto c12n = nb::class_<PyChaCha12Native>(m, "_ChaCha12Native")
                  .def(nb::init<uint64_t>(), "seed"_a)
                  .def(nb::init<uint64_t, uint64_t, uint64_t>(), "seed"_a, "counter"_a, "nonce"_a)
                  .def(nb::init<key_t, uint64_t, uint64_t>(), "key"_a, "counter"_a, "nonce"_a);
  register_base<simdrng::ChaChaNative<12>>(c12n);

  using PyChaCha20Native = PyBitGenerator<simdrng::ChaChaNative<20>>;
  auto c20n = nb::class_<PyChaCha20Native>(m, "_ChaCha20Native")
                  .def(nb::init<uint64_t>(), "seed"_a)
                  .def(nb::init<uint64_t, uint64_t, uint64_t>(), "seed"_a, "counter"_a, "nonce"_a)
                  .def(nb::init<key_t, uint64_t, uint64_t>(), "key"_a, "counter"_a, "nonce"_a);
  register_base<simdrng::ChaChaNative<20>>(c20n);
#endif

  // Philox SIMD variants — accept both (seed) and (key, counter)
  using PyPhilox4x32SIMD = PyBitGenerator<Philox4x32SIMD_t>;
  using key4x32_t = std::array<uint32_t, 2>;
  using ctr4x32_t = std::array<uint32_t, 4>;
  auto p4x32s = nb::class_<PyPhilox4x32SIMD>(m, "_Philox4x32SIMD")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key4x32_t, ctr4x32_t>(), "key"_a, "counter"_a);
  register_base<Philox4x32SIMD_t>(p4x32s);

  using PyPhilox2x32SIMD = PyBitGenerator<Philox2x32SIMD_t>;
  using key2x32_t = std::array<uint32_t, 1>;
  using ctr2x32_t = std::array<uint32_t, 2>;
  auto p2x32s = nb::class_<PyPhilox2x32SIMD>(m, "_Philox2x32SIMD")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key2x32_t, ctr2x32_t>(), "key"_a, "counter"_a);
  register_base<Philox2x32SIMD_t>(p2x32s);

  using PyPhilox4x64SIMD = PyBitGenerator<Philox4x64SIMD_t>;
  using key4x64_t = std::array<uint64_t, 2>;
  using ctr4x64_t = std::array<uint64_t, 4>;
  auto p4x64s = nb::class_<PyPhilox4x64SIMD>(m, "_Philox4x64SIMD")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key4x64_t, ctr4x64_t>(), "key"_a, "counter"_a);
  register_base<Philox4x64SIMD_t>(p4x64s);

  using PyPhilox2x64SIMD = PyBitGenerator<Philox2x64SIMD_t>;
  using key2x64_t = std::array<uint64_t, 1>;
  using ctr2x64_t = std::array<uint64_t, 2>;
  auto p2x64s = nb::class_<PyPhilox2x64SIMD>(m, "_Philox2x64SIMD")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key2x64_t, ctr2x64_t>(), "key"_a, "counter"_a);
  register_base<Philox2x64SIMD_t>(p2x64s);

#ifndef XSIMD_NO_SUPPORTED_ARCHITECTURE
  // Philox Native variants
  using PyPhilox4x32Native = PyBitGenerator<Philox4x32Native_t>;
  auto p4x32n = nb::class_<PyPhilox4x32Native>(m, "_Philox4x32Native")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key4x32_t, ctr4x32_t>(), "key"_a, "counter"_a);
  register_base<Philox4x32Native_t>(p4x32n);

  using PyPhilox2x32Native = PyBitGenerator<Philox2x32Native_t>;
  auto p2x32n = nb::class_<PyPhilox2x32Native>(m, "_Philox2x32Native")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key2x32_t, ctr2x32_t>(), "key"_a, "counter"_a);
  register_base<Philox2x32Native_t>(p2x32n);

  using PyPhilox4x64Native = PyBitGenerator<Philox4x64Native_t>;
  auto p4x64n = nb::class_<PyPhilox4x64Native>(m, "_Philox4x64Native")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key4x64_t, ctr4x64_t>(), "key"_a, "counter"_a);
  register_base<Philox4x64Native_t>(p4x64n);

  using PyPhilox2x64Native = PyBitGenerator<Philox2x64Native_t>;
  auto p2x64n = nb::class_<PyPhilox2x64Native>(m, "_Philox2x64Native")
                    .def(nb::init<uint64_t>(), "seed"_a)
                    .def(nb::init<uint64_t, uint64_t>(), "seed"_a, "counter"_a)
                    .def(nb::init<key2x64_t, ctr2x64_t>(), "key"_a, "counter"_a);
  register_base<Philox2x64Native_t>(p2x64n);
#endif
}
