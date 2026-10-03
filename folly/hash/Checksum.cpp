/*
 * Copyright (c) Meta Platforms, Inc. and affiliates.
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *     http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */

#include <folly/hash/Checksum.h>

#include <algorithm>
#include <stdexcept> // IWYU pragma: keep

#include <folly/CpuId.h>
#include <folly/detail/TrapOnAvx512.h>
#include <folly/external/fast-crc32/avx512_crc32c_v8s3x4.h> // @manual
#include <folly/external/fast-crc32/neon_crc32c_v3s4x2e_v2.h> // @manual
#include <folly/external/fast-crc32/neon_eor3_crc32_v8s2x4e_s1x2.h> // @manual
#include <folly/external/fast-crc32/neon_eor3_crc32c_v8s2x4e_s2x1.h> // @manual
#include <folly/external/fast-crc32/sse_crc32c_v8s3x3.h> // @manual
#include <folly/hash/detail/ChecksumDetail.h>

#if FOLLY_X64 && FOLLY_SSE_PREREQ(4, 2)
#include <emmintrin.h>
#endif

namespace folly {

namespace detail {

#if FOLLY_X64
namespace {
// Answered once, but reading it still costs a guard check, so a call that
// its size already settles must not reach it.
bool vendor_intel() {
  static const bool v = folly::CpuId().vendor_intel();
  return v;
}
} // namespace
#endif

uint32_t crc32c_sw(
    const uint8_t* data, size_t nbytes, uint32_t startingChecksum);
#if FOLLY_X64 && FOLLY_SSE_PREREQ(4, 2)

uint32_t crc32_sw(
    const uint8_t* data, size_t nbytes, uint32_t startingChecksum);

// Fast SIMD implementation of CRC-32 for x86 with pclmul
uint32_t crc32_hw(
    const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
  uint32_t sum = startingChecksum;
  size_t offset = 0;

  // Process unaligned bytes
  if ((uintptr_t)data & 15) {
    size_t limit = std::min(nbytes, -(uintptr_t)data & 15);
    sum = crc32_sw(data, limit, sum);
    offset += limit;
    nbytes -= limit;
  }

  if (nbytes >= 16) {
    const __m128i* vec = (const __m128i*)(data + offset);
#if FOLLY_HAS_CRC32_VPCLMUL
    const size_t vecs = nbytes / 16;
    // crc32_fold_for tests the sizes itself. Repeating them here
    // short-circuits the two queries that do not inline: a call under the
    // AMD floor reaches neither, and a call at or above the Intel floor
    // never reads the vendor. The fold picked is the same either way.
    switch (crc32_fold_for(
        vecs,
        vecs >= kCrc32Vpclmul512MinVectorsAmd && crc32_vpclmul512_usable(),
        crc32_vpclmul_usable(),
        vecs < kCrc32Vpclmul512MinVectorsIntel && vendor_intel())) {
      case Crc32Fold::kVpclmul512:
        sum = crc32_hw_aligned_vpclmul512(sum, vec, vecs);
        break;
      case Crc32Fold::kVpclmul256:
        sum = crc32_hw_aligned_vpclmul(sum, vec, vecs);
        break;
      case Crc32Fold::kScalar:
        sum = crc32_hw_aligned(sum, vec, vecs);
        break;
    }
#else
    sum = crc32_hw_aligned(sum, vec, nbytes / 16);
#endif
    offset += nbytes & ~15;
    nbytes &= 15;
  }

  // Remaining unaligned bytes
  if (nbytes == 0) {
    return sum;
  }
  return crc32_sw(data + offset, nbytes, sum);
}

bool crc32c_hw_supported() {
  return crc32c_hw_supported_sse42();
}

bool crc32c_hw_supported_sse42() {
  static folly::CpuId id;
  return id.sse42();
}

bool crc32c_hw_supported_avx512() {
  static folly::CpuId id;
  static bool supported = id.avx512vl() && !detail::hasTrapOnAvx512();
  return supported;
}

bool crc32_hw_supported() {
  static folly::CpuId id;
  return id.sse42();
}

bool crc32c_hw_supported_neon() {
  return false;
}

bool crc32c_hw_supported_neon_eor3_sha3() {
  return false;
}

bool crc32_hw_supported_neon_eor3_sha3() {
  return false;
}

#elif FOLLY_ARM_FEATURE_CRC32

// crc32_hw is defined in folly/external/nvidia/hash/Checksum.cpp

bool crc32c_hw_supported() {
  return true;
}

bool crc32c_hw_supported_sse42() {
  return false;
}

bool crc32c_hw_supported_avx512() {
  return false;
}

bool crc32c_hw_supported_neon() {
  static bool has_neon = has_neon_crc32c_v3s4x2e_v2();
  return has_neon;
}

bool crc32_hw_supported_neon_eor3_sha3() {
  static bool has_neon_eor3 = has_neon_eor3_crc32_v8s2x4e_s1x2();
  return has_neon_eor3;
}

bool crc32c_hw_supported_neon_eor3_sha3() {
  static bool has_neon_eor3 = has_neon_eor3_crc32c_v8s2x4e_s2x1();
  return has_neon_eor3;
}

bool crc32_hw_supported() {
  return true;
}

#else // FOLLY_ARM_FEATURE_CRC32

uint32_t crc32_hw(
    const uint8_t* /* data */,
    size_t /* nbytes */,
    uint32_t /* startingChecksum */) {
  throw std::runtime_error("crc32_hw is not implemented on this platform");
}

bool crc32c_hw_supported() {
  return false;
}

bool crc32c_hw_supported_sse42() {
  return false;
}

bool crc32c_hw_supported_avx512() {
  return false;
}

bool crc32_hw_supported() {
  return false;
}

bool crc32c_hw_supported_neon() {
  return false;
}

bool crc32_hw_supported_neon_eor3_sha3() {
  return false;
}

bool crc32c_hw_supported_neon_eor3_sha3() {
  return false;
}
#endif

namespace {

// Slice-by-4 CRC tables. entries[0] is the standard byte-at-a-time table:
// entries[0][i] is the CRC of byte i starting from CRC value 0.
// For k > 0, entries[k][i] is the CRC of byte i followed by k zero bytes,
// starting from CRC value 0. These are used to consume 4 input bytes per
// loop iteration, exploiting the linearity of CRC over GF(2).
template <uint32_t CRC_POLYNOMIAL_BIT_REVERSED>
struct CrcSwTable {
  uint32_t entries[4][256];
  constexpr CrcSwTable() : entries{} {
    for (uint32_t i = 0; i < 256; i++) {
      uint32_t crc = i;
      for (int j = 0; j < 8; j++) {
        crc = (crc & 1) ? (crc >> 1) ^ CRC_POLYNOMIAL_BIT_REVERSED : (crc >> 1);
      }
      entries[0][i] = crc;
    }
    for (uint32_t k = 0; k < 3; k++) {
      for (uint32_t i = 0; i < 256; i++) {
        uint32_t v = entries[k][i];
        entries[k + 1][i] = (v >> 8) ^ entries[0][v & 0xFF];
      }
    }
  }
};

} // namespace

template <uint32_t CRC_POLYNOMIAL_BIT_REVERSED>
uint32_t crc_sw(const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
  static constexpr CrcSwTable<CRC_POLYNOMIAL_BIT_REVERSED> table{};
  uint32_t crc = startingChecksum;
  // Process 4 bytes per iteration using the slice-by-4 algorithm. This is
  // mathematically equivalent to four byte-at-a-time CRC steps, by linearity
  // of CRC over GF(2).
  while (nbytes >= 4) {
    uint8_t b0 = data[0] ^ static_cast<uint8_t>(crc);
    uint8_t b1 = data[1] ^ static_cast<uint8_t>(crc >> 8);
    uint8_t b2 = data[2] ^ static_cast<uint8_t>(crc >> 16);
    uint8_t b3 = data[3] ^ static_cast<uint8_t>(crc >> 24);
    crc = table.entries[3][b0] ^ table.entries[2][b1] ^ table.entries[1][b2] ^
        table.entries[0][b3];
    data += 4;
    nbytes -= 4;
  }
  // Process any remaining bytes (0 to 3) one at a time.
  for (size_t i = 0; i < nbytes; i++) {
    crc = table.entries[0][(crc ^ data[i]) & 0xFF] ^ (crc >> 8);
  }
  return crc;
}

uint32_t crc32c_sw(
    const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
  // Bit-reversed from CRC-32C polynomial 0x1EDC6F41
  constexpr uint32_t CRC32C_POLYNOMIAL_BIT_REVERSED = 0x82F63B78;
  return crc_sw<CRC32C_POLYNOMIAL_BIT_REVERSED>(data, nbytes, startingChecksum);
}

uint32_t crc32_sw(
    const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
  // Bit-reversed from CRC-32 polynomial 0x04C11DB7
  constexpr uint32_t CRC32_POLYNOMIAL_BIT_REVERSED = 0xEDB88320;
  return crc_sw<CRC32_POLYNOMIAL_BIT_REVERSED>(data, nbytes, startingChecksum);
}

} // namespace detail

namespace {
#if FOLLY_X64
#if FOLLY_HAS_CRC32_VPCLMUL
// Whether any wider fold exists for this part at all, answered once. A part
// without VPCLMULQDQ never takes one, and this spares it the per-call tests.
bool crc32c_any_wide_fold_usable() {
  static const bool v = detail::crc32c_wide_avx512_usable() ||
      detail::crc32c_wide256_avx2_usable();
  return v;
}
#endif

// Reached by every part below the wide-fold threshold, and above it only by
// parts that cannot run a wider fold at all.
//
// The generated kernels do not cross over at the same size on both vendors, so
// the threshold is not one number. On Intel they beat crc32c_hw from 4096 up.
// On AMD the AVX-512 kernel is a sawtooth below 6144 -- 0.942x at 4096 on EPYC
// 9D64, either side of 1.070x at 4608 -- and 6144 itself is the deepest point
// at 0.881x. Eight bytes above it the kernel is already at 1.62x, so 6144 is
// both the last size that loses and the largest threshold worth having.
bool crc32c_generated_size(size_t nbytes) {
  // The size is tested first so that a call settled by its size alone never
  // touches the vendor guard variable.
  switch (detail::crc32c_generated_for(nbytes)) {
    case detail::Crc32cGenerated::kNo:
      return false;
    case detail::Crc32cGenerated::kYes:
      return true;
    case detail::Crc32cGenerated::kIntelOnly:
      break;
  }
  return detail::vendor_intel();
}
#endif
} // namespace

uint32_t crc32c(const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
#if FOLLY_X64 && FOLLY_HAS_CRC32_VPCLMUL
  // One fold per part, chosen by what it can run rather than by call size.
  // Splitting the AMD range by size was measured and is not worth its branch:
  // a single fold is within 2% of the best fold at every size on every part,
  // and within noise on three of five. Intel takes the 256-bit fold, which
  // leads there at every size measured.
  //
  // Size first, then capability. The size test is an integer compare and
  // rejects most calls, so it has to come before anything that does not
  // inline. The capability answer is read once and cached: a part with
  // neither ISA can never take any of this, and without that test it paid
  // three cross-library calls on every large call for a branch that always
  // fell through.
  if (nbytes >= detail::kCrc32cWideMinBytesAmd &&
      crc32c_any_wide_fold_usable()) {
    switch (detail::crc32c_wide_fold_for(
        nbytes,
        detail::crc32c_wide_avx512_usable(),
        detail::crc32c_wide256_avx2_usable(),
        detail::vendor_intel())) {
      case detail::Crc32cWideFold::kWide512:
        return detail::crc32c_wide512(data, nbytes, startingChecksum);
      case detail::Crc32cWideFold::kWide256Avx512:
        return detail::crc32c_wide256_avx512(data, nbytes, startingChecksum);
      case detail::Crc32cWideFold::kWide256Avx2:
        return detail::crc32c_wide256_avx2(data, nbytes, startingChecksum);
      case detail::Crc32cWideFold::kNone:
        break;
    }
  }
#endif
#if FOLLY_X64
  // available() is a cross-library call that does not inline, so it goes last:
  // a caller below the threshold must not pay for it.
  if (crc32c_generated_size(nbytes) && detail::crc32c_hw_supported_avx512() &&
      detail::avx512_crc32c_v8s3x4_available()) {
    return detail::avx512_crc32c_v8s3x4(data, nbytes, startingChecksum);
  }
#endif

#if FOLLY_AARCH64
  if (detail::crc32c_hw_supported_neon_eor3_sha3()) {
    if (nbytes < 1536) {
      return detail::neon_eor3_crc32c_small(data, nbytes, startingChecksum);
    } else {
      return detail::neon_eor3_crc32c_v8s2x4e_s2x1(
          data, nbytes, startingChecksum);
    }
  }

  if (nbytes >= 4096 && detail::crc32c_hw_supported_neon()) {
    return detail::neon_crc32c_v3s4x2e_v2(data, nbytes, startingChecksum);
  }
#endif

  if (detail::crc32c_hw_supported()) {
#if FOLLY_X64 && defined(FOLLY_ENABLE_SSE42_CRC32C_V8S3X3)
    // Above the threshold, a part that cannot run the AVX-512 kernel takes
    // this one. On EPYC 7D13 at 8 KiB that is 1.37x crc32c_hw (n=9).
    if (crc32c_generated_size(nbytes)) {
      return detail::sse_crc32c_v8s3x3(data, nbytes, startingChecksum);
    }
#endif
    return detail::crc32c_hw(data, nbytes, startingChecksum);
  } else {
    return detail::crc32c_sw(data, nbytes, startingChecksum);
  }
}

uint32_t crc32(const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
#if FOLLY_AARCH64
  if (detail::crc32_hw_supported_neon_eor3_sha3()) {
    if (nbytes < 1536) {
      return detail::neon_eor3_crc32_small(data, nbytes, startingChecksum);
    } else {
      return detail::neon_eor3_crc32_v8s2x4e_s1x2(
          data, nbytes, startingChecksum);
    }
  }
#endif

  if (detail::crc32_hw_supported()) {
    return detail::crc32_hw(data, nbytes, startingChecksum);
  } else {
    return detail::crc32_sw(data, nbytes, startingChecksum);
  }
}

uint32_t crc32_type(
    const uint8_t* data, size_t nbytes, uint32_t startingChecksum) {
  return ~crc32(data, nbytes, startingChecksum);
}

uint32_t crc32_combine(uint32_t crc1, uint32_t crc2, size_t crc2len) {
  // Append up to 32 bits of zeroes in the normal way
  uint8_t data[4] = {0, 0, 0, 0};
  auto len = crc2len & 3;
  if (len) {
    crc1 = crc32(data, len, crc1);
  }

  if (detail::crc32_hw_supported()) {
    return detail::crc32_combine_hw(crc1, crc2, crc2len);
  } else {
    return detail::crc32_combine_sw(crc1, crc2, crc2len);
  }
}

uint32_t crc32c_combine(uint32_t crc1, uint32_t crc2, size_t crc2len) {
  // Append up to 32 bits of zeroes in the normal way
  uint8_t data[4] = {0, 0, 0, 0};
  auto len = crc2len & 3;
  if (len) {
    crc1 = crc32c(data, len, crc1);
  }

  if (detail::crc32c_hw_supported()) {
    return detail::crc32c_combine_hw(crc1, crc2, crc2len - len);
  } else {
    return detail::crc32c_combine_sw(crc1, crc2, crc2len - len);
  }
}

uint32_t crc32c_combine_seed(
    uint32_t crc1, uint32_t crc2, size_t crc2len, uint32_t startingChecksum) {
  if (startingChecksum == 0U) {
    return crc32c_combine(crc1, crc2, crc2len);
  }

  crc1 ^= startingChecksum;
  crc2 ^= startingChecksum;

  // Append up to 32 bits of zeroes in the normal way
  uint8_t data[4] = {0, 0, 0, 0};
  auto len = crc2len & 3;
  if (len) {
    crc1 = crc32c(data, len, crc1);
  }

  auto result = detail::crc32c_hw_supported()
      ? detail::crc32c_combine_hw(crc1, crc2, crc2len - len)
      : detail::crc32c_combine_sw(crc1, crc2, crc2len - len);
  result ^= startingChecksum;
  return result;
}

} // namespace folly
