// SPDX-License-Identifier: Apache-2.0
// Kernels assume 16-byte bases, strides divisible by 8 and SPEC.md shapes.
// The C API validates these before launching.
#include <cstdint>
#include <limits>

#include "abi_runtime.h"
#include "validation.h"
#include "nf12/nf12.h"

namespace {

using nf12::abi::from_runtime;
using nf12::abi::from_codec;
using namespace nf12::validation;
constexpr uint32_t kMaxExpBase = 120;

bool valid_weight(const nf12_weight_t* w) {
  return w != nullptr && valid_shape(w->n, w->k) && w->packed != nullptr && aligned16(w->packed) &&
         w->exp_base <= kMaxExpBase && aligned16(w->escapes) && (w->num_escapes == 0 || w->escapes != nullptr);
}

bool valid_workspace(const void* workspace, size_t bytes) {
  return bytes == 0 || (workspace != nullptr && aligned16(workspace));
}

nf12_status_t current_device(int* device) {
  bool supported = false;
  const cudaError_t err = nf12::backend::current_device(device, &supported);
  return nf12::abi::from_device(err, supported);
}

nf12_status_t run_linear(const void* x, int64_t m, int64_t ldx, nf12::backend::WeightSource source, const void* weight,
                         const void* escapes, uint32_t num_escapes, uint32_t exp_base, int64_t n, int64_t k,
                         const void* bias, void* y, int64_t ldy, void* workspace, size_t workspace_bytes,
                         cudaStream_t stream) {
  if (m < 0 || (bias != nullptr && !aligned16(bias)) || !valid_workspace(workspace, workspace_bytes)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  if (m == 0) return NF12_OK;
  if (!valid_bf16_matrix(x, k, ldx) || !valid_bf16_matrix(y, n, ldy)) return NF12_ERROR_INVALID_ARGUMENT;
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  if (workspace_bytes < nf12::backend::linear_workspace_bytes(m, n, k, device)) return NF12_ERROR_INSUFFICIENT_WORKSPACE;

  nf12::backend::LinearArgs args{};
  args.x = x;
  args.m = m;
  args.ldx = ldx;
  args.source = source;
  args.weight = static_cast<const uint8_t*>(weight);
  args.escapes = escapes;
  args.num_escapes = num_escapes;
  args.exp_base = exp_base;
  args.n = n;
  args.k = k;
  args.bias = bias;
  args.y = y;
  args.ldy = ldy;
  args.workspace = workspace;
  args.workspace_bytes = workspace_bytes;
  args.stream = stream;
  args.device = device;
  return from_runtime(nf12::backend::linear(args));
}

bool valid_moe_weight(const nf12_moe_weight_t* w) {
  return w != nullptr && valid_moe_shape(w->num_experts, w->n, w->k) && w->packed != nullptr && aligned16(w->packed) &&
         aligned16(w->escapes) && w->escape_offsets != nullptr && aligned(w->escape_offsets, 8) &&
         w->exp_base != nullptr;
}

// Gather/scatter indices and sorted positions limit assignments to int32.
nf12_status_t run_moe_linear(const void* x, int64_t ldx, const int32_t* gather, int64_t gather_div,
                             const int32_t* scatter, const int64_t* expert_offsets, int64_t max_assignments,
                             nf12::backend::MoeLinearArgs args, const float* row_scale, void* y, int64_t ldy,
                             void* workspace, size_t workspace_bytes, cudaStream_t stream) {
  if (!valid_moe_linear_buffers(x, ldx, gather, gather_div, scatter, expert_offsets,
                                max_assignments, row_scale, y, ldy, args.n, args.k) ||
      !valid_workspace(workspace, workspace_bytes)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  if (max_assignments == 0) return NF12_OK;
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  if (workspace_bytes < nf12::backend::moe_linear_workspace_bytes(max_assignments, args.num_experts, args.n, args.k,
                                                                 device)) {
    return NF12_ERROR_INSUFFICIENT_WORKSPACE;
  }
  args.x = x;
  args.ldx = ldx;
  args.gather = gather;
  args.gather_div = gather_div;
  args.scatter = scatter;
  args.expert_offsets = expert_offsets;
  args.max_assignments = max_assignments;
  args.row_scale = row_scale;
  args.y = y;
  args.ldy = ldy;
  args.workspace = workspace;
  args.workspace_bytes = workspace_bytes;
  args.stream = stream;
  args.device = device;
  return from_runtime(nf12::backend::moe_linear(args));
}

template <typename Id>
nf12_status_t run_embedding(const nf12_weight_t* w, const Id* ids, int64_t num_ids, void* out, int64_t ldo,
                            cudaStream_t stream) {
  if (!valid_weight(w) || num_ids < 0 || !aligned(ids, sizeof(Id))) return NF12_ERROR_INVALID_ARGUMENT;
  if (num_ids == 0) return NF12_OK;
  // Bound BF16 byte offsets to int64.
  if (ids == nullptr || !valid_bf16_matrix(out, w->k, ldo) || num_ids > std::numeric_limits<int64_t>::max() / 2 / ldo) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  const int32_t* ids32 = nullptr;
  const int64_t* ids64 = nullptr;
  if constexpr (sizeof(Id) == sizeof(int32_t)) {
    ids32 = ids;
  } else {
    ids64 = ids;
  }
  return from_codec(nf12::backend::embedding(static_cast<const uint8_t*>(w->packed),
                                            w->escapes, w->num_escapes, w->exp_base, w->n,
                                            w->k, ids32, ids64, num_ids, out, ldo,
                                            stream));
}


}

extern "C" {

cudaError_t nf12_last_cuda_error(void) { return nf12::abi::last_error; }

size_t nf12_packed_bytes(int64_t n, int64_t k) {
  return valid_shape(n, k) ? static_cast<size_t>(n) * static_cast<size_t>(k) * 3 / 2 : 0;
}

size_t nf12_bf16t_bytes(int64_t n, int64_t k) {
  return valid_shape(n, k) ? static_cast<size_t>(n) * static_cast<size_t>(k) * 2 : 0;
}

size_t nf12_encode_workspace_bytes(int64_t n, int64_t k) {
  return valid_shape(n, k) ? nf12::backend::encode_workspace_bytes(n, k) : 0;
}

nf12_status_t nf12_encode_analyze(const void* w_bf16, int64_t n, int64_t k, int64_t ldw, void* workspace,
                                  size_t workspace_bytes, uint8_t* exp_base_out, uint32_t* num_escapes_out,
                                  cudaStream_t stream) {
  if (!valid_shape(n, k) || !valid_bf16_matrix(w_bf16, k, ldw) || exp_base_out == nullptr ||
      num_escapes_out == nullptr || !valid_workspace(workspace, workspace_bytes)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  if (workspace_bytes < nf12::backend::encode_workspace_bytes(n, k)) return NF12_ERROR_INSUFFICIENT_WORKSPACE;
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_codec(nf12::backend::encode_analyze(w_bf16, n, k, ldw, workspace,
                                                 workspace_bytes, exp_base_out, num_escapes_out, stream));
}

nf12_status_t nf12_encode(const void* w_bf16, int64_t n, int64_t k, int64_t ldw, uint8_t exp_base, void* packed_out,
                          void* escapes_out, uint32_t escapes_capacity, void* workspace, size_t workspace_bytes,
                          cudaStream_t stream) {
  if (!valid_shape(n, k) || !valid_bf16_matrix(w_bf16, k, ldw) || exp_base > kMaxExpBase || packed_out == nullptr ||
      !aligned16(packed_out) || !aligned16(escapes_out) || (escapes_capacity > 0 && escapes_out == nullptr) ||
      !valid_workspace(workspace, workspace_bytes)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  if (workspace_bytes < nf12::backend::encode_workspace_bytes(n, k)) return NF12_ERROR_INSUFFICIENT_WORKSPACE;
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_codec(nf12::backend::encode(w_bf16, n, k, ldw, exp_base,
                                         static_cast<uint8_t*>(packed_out), escapes_out,
                                         escapes_capacity, workspace, workspace_bytes, stream));
}

nf12_status_t nf12_decode(const nf12_weight_t* w, void* out_bf16, int64_t ldo, cudaStream_t stream) {
  if (!valid_weight(w) || !valid_bf16_matrix(out_bf16, w->k, ldo)) return NF12_ERROR_INVALID_ARGUMENT;
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_codec(nf12::backend::decode(static_cast<const uint8_t*>(w->packed), w->escapes,
                                         w->exp_base, w->n, w->k, out_bf16, ldo, stream));
}

size_t nf12_linear_workspace_bytes(int64_t m, int64_t n, int64_t k, int device) {
  if (m <= 0 || !valid_shape(n, k)) return 0;
  return nf12::backend::device_supported(device) ? nf12::backend::linear_workspace_bytes(m, n, k, device) : 0;
}

int64_t nf12_linear_decode_gemm_rows(int64_t m, int64_t n, int64_t k, int device) {
  if (m <= 0 || m > std::numeric_limits<int32_t>::max() || !valid_shape(n, k)) return 0;
  return nf12::backend::device_supported(device) ? nf12::backend::linear_decode_gemm_rows(m, n, k, device) : 0;
}

nf12_status_t nf12_linear(const void* x_bf16, int64_t m, int64_t ldx, const nf12_weight_t* w, const void* bias_bf16,
                          void* y_bf16, int64_t ldy, void* workspace, size_t workspace_bytes, cudaStream_t stream) {
  if (!valid_weight(w)) return NF12_ERROR_INVALID_ARGUMENT;
  return run_linear(x_bf16, m, ldx, nf12::backend::WeightSource::kNF12, w->packed, w->escapes, w->num_escapes,
                    w->exp_base, w->n, w->k, bias_bf16, y_bf16, ldy, workspace, workspace_bytes, stream);
}

nf12_status_t nf12_pack_bf16t(const void* w_bf16, int64_t n, int64_t k, int64_t ldw, void* out, cudaStream_t stream) {
  if (!valid_shape(n, k) || !valid_bf16_matrix(w_bf16, k, ldw) || out == nullptr || !aligned16(out)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_codec(nf12::backend::pack_bf16t(w_bf16, n, k, ldw,
                                             static_cast<uint8_t*>(out), stream));
}

nf12_status_t nf12_linear_bf16t(const void* x_bf16, int64_t m, int64_t ldx, const void* w_bf16t, int64_t n, int64_t k,
                                const void* bias_bf16, void* y_bf16, int64_t ldy, void* workspace,
                                size_t workspace_bytes, cudaStream_t stream) {
  if (!valid_shape(n, k) || w_bf16t == nullptr || !aligned16(w_bf16t)) return NF12_ERROR_INVALID_ARGUMENT;
  return run_linear(x_bf16, m, ldx, nf12::backend::WeightSource::kBF16T, w_bf16t, nullptr, 0, 0, n, k, bias_bf16,
                    y_bf16, ldy, workspace, workspace_bytes, stream);
}

size_t nf12_moe_align_workspace_bytes(int64_t num_tokens, int64_t topk, int64_t num_experts) {
  if (num_tokens < 0 || topk < 1 || num_experts < 1 || num_experts > std::numeric_limits<int32_t>::max() ||
      num_tokens > std::numeric_limits<int32_t>::max() / topk) {
    return 0;
  }
  return nf12::backend::moe_align_workspace_bytes(num_tokens, topk, num_experts);
}

nf12_status_t nf12_moe_align(const int32_t* topk_ids, int64_t num_tokens, int64_t topk, int64_t num_experts,
                             int32_t* sorted_out, int64_t* expert_offsets_out, void* workspace,
                             size_t workspace_bytes, cudaStream_t stream) {
  // Assignment positions and expert IDs must fit in int32.
  if (num_tokens < 0 || topk < 1 || num_experts < 1 || num_experts > std::numeric_limits<int32_t>::max() ||
      num_tokens > std::numeric_limits<int32_t>::max() / topk || expert_offsets_out == nullptr ||
      !aligned(expert_offsets_out, 8) || !aligned(topk_ids, 4) || !aligned(sorted_out, 4) ||
      !valid_workspace(workspace, workspace_bytes)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  // Empty input still writes zero offsets, but needs no ID/sorted buffers.
  if (num_tokens > 0 && (topk_ids == nullptr || sorted_out == nullptr)) return NF12_ERROR_INVALID_ARGUMENT;
  if (workspace_bytes < nf12::backend::moe_align_workspace_bytes(num_tokens, topk, num_experts)) {
    return NF12_ERROR_INSUFFICIENT_WORKSPACE;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_runtime(nf12::backend::moe_align(topk_ids, num_tokens, topk, num_experts, sorted_out, expert_offsets_out,
                                           workspace, workspace_bytes, stream));
}

size_t nf12_moe_linear_workspace_bytes(int64_t max_assignments, int64_t num_experts, int64_t n, int64_t k,
                                       int device) {
  if (max_assignments <= 0 || max_assignments > std::numeric_limits<int32_t>::max() ||
      !valid_moe_shape(num_experts, n, k)) {
    return 0;
  }
  return nf12::backend::device_supported(device) ? nf12::backend::moe_linear_workspace_bytes(max_assignments, num_experts, n, k, device) : 0;
}

nf12_status_t nf12_moe_linear(const void* x_bf16, int64_t ldx, const int32_t* gather, int64_t gather_div,
                              const int32_t* scatter, const int64_t* expert_offsets, int64_t max_assignments,
                              const nf12_moe_weight_t* w, const float* row_scale, void* y_bf16, int64_t ldy,
                              void* workspace, size_t workspace_bytes, cudaStream_t stream) {
  if (!valid_moe_weight(w)) return NF12_ERROR_INVALID_ARGUMENT;
  nf12::backend::MoeLinearArgs args{};
  args.source = nf12::backend::WeightSource::kNF12;
  args.weight = static_cast<const uint8_t*>(w->packed);
  args.escapes = w->escapes;
  args.escape_offsets = w->escape_offsets;
  args.exp_base = w->exp_base;
  args.num_experts = w->num_experts;
  args.n = w->n;
  args.k = w->k;
  return run_moe_linear(x_bf16, ldx, gather, gather_div, scatter, expert_offsets, max_assignments, args, row_scale,
                        y_bf16, ldy, workspace, workspace_bytes, stream);
}

nf12_status_t nf12_moe_linear_bf16t(const void* x_bf16, int64_t ldx, const int32_t* gather, int64_t gather_div,
                                    const int32_t* scatter, const int64_t* expert_offsets, int64_t max_assignments,
                                    const void* w_bf16t, int64_t num_experts, int64_t n, int64_t k,
                                    const float* row_scale, void* y_bf16, int64_t ldy, void* workspace,
                                    size_t workspace_bytes, cudaStream_t stream) {
  if (!valid_moe_shape(num_experts, n, k) || w_bf16t == nullptr || !aligned16(w_bf16t)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  nf12::backend::MoeLinearArgs args{};
  args.source = nf12::backend::WeightSource::kBF16T;
  args.weight = static_cast<const uint8_t*>(w_bf16t);
  args.num_experts = num_experts;
  args.n = n;
  args.k = k;
  return run_moe_linear(x_bf16, ldx, gather, gather_div, scatter, expert_offsets, max_assignments, args, row_scale,
                        y_bf16, ldy, workspace, workspace_bytes, stream);
}

nf12_status_t nf12_moe_combine(const void* y_bf16, int64_t ldy, int64_t num_tokens, int64_t topk, int64_t n,
                               void* out_bf16, int64_t ldo, cudaStream_t stream) {
  constexpr int64_t kMax = std::numeric_limits<int64_t>::max();
  if (num_tokens < 0 || topk < 1 || topk > std::numeric_limits<int32_t>::max() || n <= 0 || n % 8 != 0) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  if (num_tokens == 0) return NF12_OK;
  // Bound BF16 byte offsets in both buffers to int64.
  if (!valid_bf16_matrix(y_bf16, n, ldy) || !valid_bf16_matrix(out_bf16, n, ldo) ||
      num_tokens > kMax / 2 / topk / ldy || num_tokens > kMax / 2 / ldo) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_runtime(nf12::backend::moe_combine(y_bf16, ldy, num_tokens, topk, n,
                                             out_bf16, ldo, stream));
}

nf12_status_t nf12_moe_silu_mul(const void* h_bf16, int64_t ldh, int64_t rows, int64_t inter, void* out_bf16,
                                int64_t ldo, cudaStream_t stream) {
  constexpr int64_t kMax = std::numeric_limits<int64_t>::max();
  if (rows < 0 || inter <= 0 || inter % 8 != 0 || inter > kMax / 2) return NF12_ERROR_INVALID_ARGUMENT;
  if (rows == 0) return NF12_OK;
  // Bound BF16 byte offsets in both buffers to int64.
  if (!valid_bf16_matrix(h_bf16, 2 * inter, ldh) || !valid_bf16_matrix(out_bf16, inter, ldo) ||
      rows > kMax / 2 / ldh || rows > kMax / 2 / ldo) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_runtime(nf12::backend::moe_silu_mul(h_bf16, ldh, rows, inter,
                                              out_bf16, ldo, stream));
}

nf12_status_t nf12_moe_decode(const nf12_moe_weight_t* w, const int64_t* expert_offsets, int64_t max_assignments,
                              int64_t row0, int64_t rows, void* out_bf16, int64_t ldo, cudaStream_t stream) {
  if (!valid_moe_weight(w) || row0 < 0 || rows < 0 || row0 % 16 != 0 || rows % 16 != 0 || rows > w->n - row0 ||
      !aligned(expert_offsets, 8) || max_assignments < 0 || max_assignments > std::numeric_limits<int32_t>::max()) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  if (rows == 0) return NF12_OK;
  // Bound stacked BF16 output byte offsets to int64.
  if (!valid_bf16_matrix(out_bf16, w->k, ldo) || w->num_experts > std::numeric_limits<int64_t>::max() / 2 / rows / ldo) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_codec(nf12::backend::moe_decode(static_cast<const uint8_t*>(w->packed),
                                             w->escapes, w->escape_offsets, w->exp_base,
                                             w->num_experts, w->n, w->k, expert_offsets, max_assignments, row0, rows,
                                             out_bf16, ldo, stream));
}

int64_t nf12_moe_linear_decode_gemm_rows(int64_t max_assignments, int64_t num_experts, int64_t n, int64_t k,
                                         int device) {
  if (max_assignments <= 0 || max_assignments > std::numeric_limits<int32_t>::max() ||
      !valid_moe_shape(num_experts, n, k)) {
    return 0;
  }
  return nf12::backend::device_supported(device) ? nf12::backend::moe_linear_decode_gemm_rows(max_assignments, num_experts, n, k, device) : 0;
}

nf12_status_t nf12_moe_grouped_operands(const void* x_bf16, int64_t ldx, const int32_t* gather, int64_t gather_div,
                                        const int64_t* expert_offsets, int64_t max_assignments, int64_t num_experts,
                                        int64_t k, void* x_out_bf16, int64_t ldo, int32_t* group_ends,
                                        cudaStream_t stream) {
  constexpr int64_t kMax = std::numeric_limits<int64_t>::max();
  if (max_assignments < 0 || max_assignments > std::numeric_limits<int32_t>::max() || gather_div < 1 ||
      num_experts < 1 || num_experts > std::numeric_limits<int32_t>::max() ||
      k <= 0 || k % 8 != 0 || expert_offsets == nullptr || !aligned(expert_offsets, 8) ||
      group_ends == nullptr || !aligned(group_ends, 4) || !aligned(gather, 4)) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  // Gather can address any int32 row, regardless of max_assignments.
  if (gather != nullptr && (!valid_bf16_matrix(x_bf16, k, ldx) || !valid_bf16_matrix(x_out_bf16, k, ldo) ||
                            ldx > kMax / 2 / std::numeric_limits<int32_t>::max() ||
                            ldo > kMax / 2 / std::numeric_limits<int32_t>::max())) {
    return NF12_ERROR_INVALID_ARGUMENT;
  }
  int device = 0;
  if (nf12_status_t s = current_device(&device); s != NF12_OK) return s;
  return from_runtime(nf12::backend::moe_grouped_operands(
      x_bf16, ldx, gather, gather_div, expert_offsets, max_assignments,
      num_experts, k, x_out_bf16, ldo, group_ends, stream));
}

nf12_status_t nf12_embedding(const nf12_weight_t* w, const int32_t* ids, int64_t num_ids, void* out_bf16, int64_t ldo,
                             cudaStream_t stream) {
  return run_embedding(w, ids, num_ids, out_bf16, ldo, stream);
}

nf12_status_t nf12_embedding_i64(const nf12_weight_t* w, const int64_t* ids, int64_t num_ids, void* out_bf16,
                                 int64_t ldo, cudaStream_t stream) {
  return run_embedding(w, ids, num_ids, out_bf16, ldo, stream);
}

}
