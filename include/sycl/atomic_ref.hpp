/**
 * Copyright (c) 2026 Centre for Development of Advanced Computing (C-DAC)
 *
 * This file is part of the ParaS Compiler, a component of the ParaS Ecosystem.
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *     https://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 *
 * SPDX-License-Identifier: Apache-2.0
 */

#ifndef __PARAS_ATOMIC_REF_HPP__
#define __PARAS_ATOMIC_REF_HPP__

#include "access.hpp"
#include <cstddef>
#include <cstdint>
#include <cstring>
#include <type_traits>

#if !PARAS_GPU_BACKEND
#include <atomic>
#endif

namespace sycl {

enum class memory_order { relaxed, acquire, release, acq_rel, seq_cst };
enum class memory_scope { work_item, sub_group, work_group, device, system };

template <memory_order> struct memory_order_traits;

template <> struct memory_order_traits<memory_order::relaxed> {
  static constexpr memory_order read_order = memory_order::relaxed;
  static constexpr memory_order write_order = memory_order::relaxed;
};

template <> struct memory_order_traits<memory_order::acq_rel> {
  static constexpr memory_order read_order = memory_order::acquire;
  static constexpr memory_order write_order = memory_order::release;
};

template <> struct memory_order_traits<memory_order::seq_cst> {
  static constexpr memory_order read_order = memory_order::seq_cst;
  static constexpr memory_order write_order = memory_order::seq_cst;
};

#if !PARAS_GPU_BACKEND
inline constexpr std::memory_order to_std(memory_order o) {
  switch (o) {
  case memory_order::relaxed:
    return std::memory_order_relaxed;
  case memory_order::acquire:
    return std::memory_order_acquire;
  case memory_order::release:
    return std::memory_order_release;
  case memory_order::acq_rel:
    return std::memory_order_acq_rel;
  case memory_order::seq_cst:
    return std::memory_order_seq_cst;
  }
  return std::memory_order_seq_cst;
}
#endif

#if PARAS_GPU_BACKEND

template <size_t Bytes> struct paras_cas_uint;
template <> struct paras_cas_uint<4> { using type = unsigned int; };
template <> struct paras_cas_uint<8> { using type = unsigned long long; };


template <typename To, typename From>
PARAS_KERNEL_HD To reinterpret_bits(const From &src) noexcept {
  static_assert(sizeof(To) == sizeof(From),
                "reinterpret_bits requires matching sizes");
  To dst;
  memcpy(&dst, &src, sizeof(To));
  return dst;
}
#endif

template <typename T, memory_order DefaultOrder = memory_order::relaxed,
          memory_scope DefaultScope = memory_scope::device,
          access::address_space AddressSpace =
              access::address_space::generic_space>
class atomic_ref {
public:
  using value_type = T;
  static constexpr size_t required_alignment = alignof(T);

#if PARAS_GPU_BACKEND
  static constexpr bool is_always_lock_free = true;
#else
  static constexpr bool is_always_lock_free =
      std::atomic<T>::is_always_lock_free;
#endif

  static constexpr memory_order default_read_order =
      memory_order_traits<DefaultOrder>::read_order;
  static constexpr memory_order default_write_order =
      memory_order_traits<DefaultOrder>::write_order;
  static constexpr memory_order default_read_modify_write_order = DefaultOrder;
  static constexpr memory_scope default_scope = DefaultScope;

private:
  T *ptr;

#if !PARAS_GPU_BACKEND
  std::atomic<T> *atomic_ptr() const noexcept {
    return reinterpret_cast<std::atomic<T> *>(ptr);
  }
#endif

#if PARAS_GPU_BACKEND
 
  template <typename BinOp>
  PARAS_KERNEL_HD T cas_loop_word(T v, BinOp op) const noexcept {
    using U = typename paras_cas_uint<sizeof(T)>::type;
    U *uptr = reinterpret_cast<U *>(ptr);
    U old_bits = *uptr;
    U assumed_bits;
    do {
      assumed_bits = old_bits;
      T assumed_val = reinterpret_bits<T>(assumed_bits);
      T new_val = op(assumed_val, v);
      U new_bits = reinterpret_bits<U>(new_val);
      old_bits = atomicCAS(uptr, assumed_bits, new_bits);
    } while (assumed_bits != old_bits);
    return reinterpret_bits<T>(old_bits);
  }

  template <typename BinOp>
  PARAS_KERNEL_HD T cas_loop_masked16(T v, BinOp op) const noexcept {
    uintptr_t addr = reinterpret_cast<uintptr_t>(ptr);
    uintptr_t aligned_addr = addr & ~uintptr_t(3);
    unsigned int byte_offset = static_cast<unsigned int>(addr - aligned_addr);
    unsigned int shift = byte_offset * 8;
    unsigned int mask = 0xFFFFu << shift;
    unsigned int *word_ptr = reinterpret_cast<unsigned int *>(aligned_addr);
    unsigned int old_word = *word_ptr;
    unsigned int assumed_word;

    do {
      assumed_word = old_word;
      unsigned short assumed_half =static_cast<unsigned short>((assumed_word >> shift) & 0xFFFFu);
      T assumed_val = reinterpret_bits<T>(assumed_half);
      T new_val = op(assumed_val, v);
      unsigned short new_half =reinterpret_bits<unsigned short>(new_val);
      unsigned int new_word =(assumed_word & ~mask) | (static_cast<unsigned int>(new_half) << shift);
      old_word = atomicCAS(word_ptr, assumed_word, new_word);
      
    } while (assumed_word != old_word);

    unsigned short old_half = static_cast<unsigned short>((old_word >> shift) & 0xFFFFu);
    return reinterpret_bits<T>(old_half);
  }

  template <typename BinOp>
  PARAS_KERNEL_HD T cas_loop(T v, BinOp op) const noexcept {
    if constexpr (sizeof(T) == 2) {
      return cas_loop_masked16(v, op);
    } else {
      return cas_loop_word(v, op);
    }
  }
#endif

public:
  PARAS_KERNEL_HD
  explicit atomic_ref(T &ref) : ptr(&ref) {}

  PARAS_KERNEL_HD
  void store(T v, memory_order o = default_write_order,
             memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    *ptr = v;
#else
    atomic_ptr()->store(v, to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  T load(memory_order o = default_read_order,
         memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return *ptr;
#else
    return atomic_ptr()->load(to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  operator T() const noexcept { return load(); }

  PARAS_KERNEL_HD
  T fetch_add(T v, memory_order o = default_read_modify_write_order,
              memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return static_cast<T>(a + b);
    });
#else
    return atomic_ptr()->fetch_add(v, to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  T fetch_sub(T v, memory_order o = default_read_modify_write_order,
              memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return static_cast<T>(a - b);
    });
#else
    return atomic_ptr()->fetch_sub(v, to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  T fetch_or(T v, memory_order o = default_read_modify_write_order,
             memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return static_cast<T>(a | b);
    });
#else
    return atomic_ptr()->fetch_or(v, to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  T fetch_xor(T v, memory_order o = default_read_modify_write_order,
              memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return static_cast<T>(a ^ b);
    });
#else
    return atomic_ptr()->fetch_xor(v, to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  T fetch_and(T v, memory_order o = default_read_modify_write_order,
              memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return static_cast<T>(a & b);
    });
#else
    return atomic_ptr()->fetch_and(v, to_std(o));
#endif
  }

  PARAS_KERNEL_HD
  T fetch_min(T v, memory_order o = default_read_modify_write_order,
              memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return b < a ? b : a;
    });
#else
    T old = atomic_ptr()->load(to_std(o));
    while (v < old &&
           !atomic_ptr()->compare_exchange_weak(old, v, to_std(o), to_std(o))) {
    }
    return old;
#endif
  }

  PARAS_KERNEL_HD
  T fetch_max(T v, memory_order o = default_read_modify_write_order,
              memory_scope = default_scope) const noexcept {
#if PARAS_GPU_BACKEND
    return cas_loop(v, [] PARAS_KERNEL_HD(T a, T b) {
      return b > a ? b : a;
    });
#else
    T old = atomic_ptr()->load(to_std(o));
    while (v > old &&
           !atomic_ptr()->compare_exchange_weak(old, v, to_std(o), to_std(o))) {
    }
    return old;
#endif
  }

  PARAS_KERNEL_HD T operator+=(T v) const noexcept { return fetch_add(v) + v; }
  PARAS_KERNEL_HD T operator-=(T v) const noexcept { return fetch_sub(v) - v; }
  PARAS_KERNEL_HD T operator|=(T v) const noexcept { return fetch_or(v) | v; }
  PARAS_KERNEL_HD T operator^=(T v) const noexcept { return fetch_xor(v) ^ v; }
  PARAS_KERNEL_HD T operator&=(T v) const noexcept { return fetch_and(v) & v; }

  PARAS_KERNEL_HD T min(T v) const noexcept { return fetch_min(v); }
  PARAS_KERNEL_HD T max(T v) const noexcept { return fetch_max(v); }
};

} // namespace sycl

#endif