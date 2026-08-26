/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

#include "radius.h"
#include <acl/acl_base.h>
#include <algorithm>
#include <cmath>
#include <cstdlib>
#include <cstdint>
#include <vector>
#include "radius/op_kernel/arch35/radius_kernel.h"
#include "radius/op_kernel/arch35/radius_tiling.h"
#include "tiling/platform/platform_ascendc.h"

namespace {

struct GridHostData {
    bool use_grid = false;
    int64_t grid_cell_count = 0;
    torch::Tensor cell_offsets;        // CPU int64, dense [batch_size*grid_cell_count + 1]
    torch::Tensor reordered_x;         // CPU, same dtype as x
    torch::Tensor reordered_orig_idx;  // CPU int64
    RadiusGridConfig config{};
};

torch::Tensor EmptyEdgeIndex(const torch::Tensor& like) {
    return torch::empty({2, 0},
                        torch::TensorOptions().dtype(torch::kLong).device(like.device()));
}

// Common grid geometry shared by the CPU and device grid builders: derive the
// axis dims and dense cell count from the bbox and cell size, with the same
// guard rails both builders apply. Returns false when the grid is unusable
// (degenerate radius, oversized / overly fine grid).
bool ComputeGridDims(const float* min_ptr, const float* max_ptr, float cell_size,
                     int64_t& out_cell_count, int64_t dims[3]) {
    if (cell_size <= 0.0f) {
        return false;
    }
    for (int d = 0; d < 3; ++d) {
        if (!std::isfinite(min_ptr[d]) || !std::isfinite(max_ptr[d])) {
            return false;
        }
        dims[d] = static_cast<int64_t>(
                      std::floor((static_cast<double>(max_ptr[d]) -
                                  static_cast<double>(min_ptr[d])) /
                                 static_cast<double>(cell_size))) +
                  1;
        dims[d] = std::max<int64_t>(dims[d], 1);
    }
    if (dims[0] > (1LL << 20) || dims[1] > (1LL << 20) || dims[2] > (1LL << 20)) {
        return false;
    }
    const int64_t cell_count = dims[0] * dims[1] * dims[2];
    if (cell_count > (1LL << 31)) {
        return false;
    }
    constexpr int64_t kMaxDenseCells = 4 * 1024 * 1024;  // ~32MB cell_starts
    if (cell_count > kMaxDenseCells) {
        return false;
    }
    out_cell_count = cell_count;
    return true;
}

bool GridEligible(int64_t feature_dim, int64_t n, int64_t m,
                  int64_t max_num_neighbors) {
    // Spatial grid: sort x by (batch, cell) so neighbors cluster in memory.
    // The kernel probes the 27 neighbor cells but SCANS CANDIDATES IN x-INDEX
    // ORDER (not cell-major order) to guarantee the ascending-neighbor order
    // the official test_radius.py requires (`torch.equal`). Disabled when the
    // input is not 3D or K > 64 (kernel uses a fixed-size per-query buffer).
    return feature_dim == 3 && n >= 8 && m >= 8 &&
           n < (1LL << 31) && max_num_neighbors <= 64;
}

// Fill the GridHostData fields common to both builders.
void FinalizeGrid(GridHostData& out, int64_t cell_count, float cell_size,
                  const float* min_ptr, const int64_t dims[3],
                  torch::Tensor cell_offsets, torch::Tensor reordered_x,
                  torch::Tensor reordered_idx) {
    out.use_grid = true;
    out.grid_cell_count = cell_count;
    out.cell_offsets = std::move(cell_offsets);
    out.reordered_x = std::move(reordered_x);
    out.reordered_orig_idx = std::move(reordered_idx);
    out.config.cell_size = cell_size;
    out.config.origin[0] = min_ptr[0];
    out.config.origin[1] = min_ptr[1];
    out.config.origin[2] = min_ptr[2];
    out.config.dims[0] = dims[0];
    out.config.dims[1] = dims[1];
    out.config.dims[2] = dims[2];
}

// Sort-key decode helpers: the compact key is (batch*cellcount + cell)*n +
// original_index, so the original index is key % n and the cell id is key / n.
// n is guaranteed > 0 by the caller (radius_npu rejects empty inputs), but the
// guards keep the codecheck divisor analysis happy.
inline int64_t OrigIndex(int64_t key, int64_t n) {
    return (n > 0) ? (key % n) : 0;
}

inline int64_t CellKey(int64_t key, int64_t n) {
    return (n > 0) ? (key / n) : 0;
}

// Per-point batch id tensor, filled from the prefix-sum ptr when batched.
torch::Tensor BuildBatchIds(const torch::Tensor& ptr_x_cpu, int64_t batch_size,
                            int64_t n) {
    auto batch_ids_t =
        torch::zeros({n}, torch::TensorOptions().dtype(torch::kLong));
    if (batch_size <= 1) {
        return batch_ids_t;
    }
    const int64_t* ptr = ptr_x_cpu.data_ptr<int64_t>();
    auto* bid = batch_ids_t.data_ptr<int64_t>();
    for (int64_t b = 0; b < batch_size; ++b) {
        for (int64_t i = ptr[b]; i < ptr[b + 1]; ++i) {
            bid[i] = b;
        }
    }
    return batch_ids_t;
}

// Dense offset table: cell_starts[k] = first reordered index of key k,
// cell_starts[K] = n (K = batch_size*grid_cell_count). Empty cells have start
// == the next non-empty cell's start (empty range). Kernel indexes
// cell_starts[cell_id] directly (O(1), no binary search).
torch::Tensor BuildCellStarts(const std::vector<int64_t>& cell_keys,
                              int64_t total_cells, int64_t n) {
    std::vector<int64_t> cell_starts(total_cells + 1, n);
    std::vector<int64_t> first_of(total_cells, -1);
    for (int64_t pos = 0; pos < n; ++pos) {
        int64_t key = cell_keys[pos];
        TORCH_CHECK(key >= 0 && key < total_cells,
                    "radius BuildCellStarts: cell key out of range");
        if (first_of[key] < 0) first_of[key] = pos;
    }
    for (int64_t k = 0; k < total_cells; ++k) {
        if (first_of[k] >= 0) cell_starts[k] = first_of[k];
    }
    int64_t next_start = n;
    for (int64_t k = total_cells - 1; k >= 0; --k) {
        if (first_of[k] >= 0) {
            next_start = first_of[k];
        } else {
            cell_starts[k] = next_start;
        }
    }
    cell_starts[total_cells] = n;

    return torch::from_blob(cell_starts.data(),
                            {total_cells + 1},
                            torch::TensorOptions().dtype(torch::kLong))
        .clone();
}

// Compute the flattened cell id for each point: cell_t = c0*(d1*d2) + c1*d2 +
// c2, with each axis coordinate floor-divided by cell_size and clamped.
// The divisor is clamped to a small positive constant so the division can
// never be by zero (codecheck G.EXP.22); a non-positive cell_size falls back
// to the same floor/clamp on a 1e-9f grid, which callers treat as unusable.
torch::Tensor ComputeCellIds(const torch::Tensor& x_f32, const float* min_ptr,
                             float cell_size, const int64_t dims[3]) {
    const float cs = (cell_size > 0.0f) ? cell_size : 1e-9f;
    if (cs == 0.0f) {
        return torch::zeros({x_f32.size(0)},
                            torch::TensorOptions().dtype(torch::kLong));
    }
    auto cell0 = ((x_f32.select(1, 0) - min_ptr[0]) / cs)
                     .floor()
                     .clamp(0, dims[0] - 1)
                     .to(torch::kLong);
    auto cell1 = ((x_f32.select(1, 1) - min_ptr[1]) / cs)
                     .floor()
                     .clamp(0, dims[1] - 1)
                     .to(torch::kLong);
    auto cell2 = ((x_f32.select(1, 2) - min_ptr[2]) / cs)
                     .floor()
                     .clamp(0, dims[2] - 1)
                     .to(torch::kLong);
    return cell0 * (dims[1] * dims[2]) + cell1 * dims[2] + cell2;
}

// Dense offset table from per-cell counts via device bincount + cumsum:
// offsets[k] = sum of counts < k (empty cells contribute 0, so start==end
// makes the kernel skip them).
torch::Tensor BuildOffsetsDevice(const torch::Tensor& x_dev,
                                 const torch::Tensor& cell_t,
                                 int64_t grid_cell_count) {
    torch::Tensor cell_counts =
        torch::bincount(cell_t, {}, static_cast<int64_t>(grid_cell_count));
    auto offsets_tensor =
        torch::zeros({grid_cell_count + 1},
                     torch::TensorOptions().dtype(torch::kLong).device(x_dev.device()));
    offsets_tensor.narrow(0, 1, grid_cell_count).copy_(torch::cumsum(cell_counts, 0));
    return offsets_tensor;
}

GridHostData BuildGrid(const torch::Tensor& x_cpu,
                       const torch::Tensor& ptr_x_cpu,
                       int64_t batch_size, double r, int64_t n,
                       int64_t m, int64_t feature_dim,
                       int64_t max_num_neighbors) {
    TORCH_CHECK(r > 0.0, "radius BuildGrid: r must be > 0");
    GridHostData out;
    if (!GridEligible(feature_dim, n, m, max_num_neighbors)) {
        return out;
    }

    // Compute cells in the input precision (float32) to avoid the to(double)
    // pass (saves ~1ms at N=8K). min/max and cell indices are exact in fp32
    // for the benchmark scale.
    auto x_f32 = x_cpu.to(torch::kFloat);
    auto min_vals = std::get<0>(x_f32.min(0));
    auto max_vals = std::get<0>(x_f32.max(0));
    const float* min_ptr = min_vals.data_ptr<float>();
    const float* max_ptr = max_vals.data_ptr<float>();

    const float cell_size = static_cast<float>(r);
    int64_t dims[3];
    int64_t grid_cell_count = 0;
    if (!ComputeGridDims(min_ptr, max_ptr, cell_size, grid_cell_count, dims)) {
        return out;
    }

    auto cell_t = ComputeCellIds(x_f32, min_ptr, cell_size, dims);

    // Build a compact int64 sort key tensor: key = (batch*cellcount + cell)*n
    // + original_index, then torch::sort (vectorized). Original index is
    // recovered from key % n. n < 2^31 so the encoding is lossless.
    torch::Tensor batch_ids_t =
        BuildBatchIds(ptr_x_cpu, batch_size, n);
    auto arange_t = torch::arange(n, torch::TensorOptions().dtype(torch::kLong));
    torch::Tensor keys_t =
        (batch_ids_t * grid_cell_count + cell_t) * n + arange_t;
    torch::Tensor sorted_keys = std::get<0>(torch::sort(keys_t));
    const int64_t* keys_ptr = sorted_keys.data_ptr<int64_t>();

    // Build the permutation ONCE as a dense int64 index and apply it with a
    // single vectorized index_select.
    std::vector<int64_t> orig_order(n);
    std::vector<int64_t> cell_keys(n);
    for (int64_t pos = 0; pos < n; ++pos) {
        int64_t k = keys_ptr[pos];
        orig_order[pos] = OrigIndex(k, n);
        cell_keys[pos] = CellKey(k, n);
    }
    auto orig_idx = torch::from_blob(
                        orig_order.data(), {n},
                        torch::TensorOptions().dtype(torch::kLong))
                        .clone();
    torch::Tensor reordered_x = x_cpu.index_select(0, orig_idx);
    torch::Tensor reordered_idx = orig_idx.clone();

    const int64_t total_cells = batch_size * grid_cell_count;
    torch::Tensor offsets_tensor =
        BuildCellStarts(cell_keys, total_cells, n);

    FinalizeGrid(out, grid_cell_count, cell_size, min_ptr, dims,
                 offsets_tensor, reordered_x, reordered_idx);
    return out;
}

// Device-side grid build for the single-batch fast path. Grid construction
// (min/max, cell assign, sort, index_select) runs entirely on the device,
// removing the x.cpu() round-trip and CPU-side torch.sort which degrades
// badly under the cgroup CPU quota at N>=32K. Only used when batch_size == 1.
GridHostData BuildGridDevice(const torch::Tensor& x_dev,
                             double r, int64_t n,
                             int64_t m, int64_t feature_dim,
                             int64_t max_num_neighbors) {
    TORCH_CHECK(r > 0.0, "radius BuildGridDevice: r must be > 0");
    GridHostData out;
    if (!GridEligible(feature_dim, n, m, max_num_neighbors)) {
        return out;
    }

    auto x_f32 = x_dev.to(torch::kFloat);
    auto min_vals = std::get<0>(x_f32.min(0));
    auto max_vals = std::get<0>(x_f32.max(0));
    auto min_cpu = min_vals.cpu();
    auto max_cpu = max_vals.cpu();
    const float* min_ptr = min_cpu.data_ptr<float>();
    const float* max_ptr = max_cpu.data_ptr<float>();

    const float cell_size = static_cast<float>(r);
    int64_t dims[3];
    int64_t grid_cell_count = 0;
    if (!ComputeGridDims(min_ptr, max_ptr, cell_size, grid_cell_count, dims)) {
        return out;
    }

    auto cell_t = ComputeCellIds(x_f32, min_ptr, cell_size, dims);

    auto arange_t = torch::arange(n, torch::TensorOptions().dtype(torch::kLong).device(x_dev.device()));
    torch::Tensor keys_t = cell_t * n + arange_t;
    auto sorted_pair = torch::sort(keys_t);
    torch::Tensor orig_idx = std::get<1>(sorted_pair);
    torch::Tensor reordered_x = x_dev.index_select(0, orig_idx);
    torch::Tensor reordered_idx = orig_idx.clone();

    torch::Tensor offsets_tensor =
        BuildOffsetsDevice(x_dev, cell_t, grid_cell_count);

    FinalizeGrid(out, grid_cell_count, cell_size, min_ptr, dims,
                 offsets_tensor, reordered_x, reordered_idx);
    return out;
}

// The sandbox container is capped at a fixed CPU quota
// (measured cpu.cfs_quota_us = 3.2M us / 100ms period = 32 cores). torch's
// default intra-op pool spawns 128 threads; a burst of min/max/sort on the
// host grid path overshoots the quota and the whole process is frozen for
// ~78ms (cgroup CFS throttling) every few calls. Bounding the pool to the
// quota during grid build eliminates the throttling with negligible BuildGrid
// cost (N<=64K ops are sub-ms single-threaded). The bound is scoped: set
// before build, restored after, so the operator never leaves a global thread
// limit behind.
int32_t NumThreadsCap() {
    const char* env = std::getenv("RADIUS_NUM_THREADS");
    if (env != nullptr) {
        int32_t v = std::atoi(env);
        if (v >= 1 && v <= 256) return v;
    }
    return 32;  // == measured cgroup quota (32 cores)
}

class NumThreadsGuard {
public:
    explicit NumThreadsGuard(int32_t cap) : prev_(torch::get_num_threads()) {
        changed_ = prev_ > cap;
        if (changed_) {
            torch::set_num_threads(cap);
        }
    }

    ~NumThreadsGuard() {
        if (changed_) {
            torch::set_num_threads(prev_);
        }
    }

private:
    int32_t prev_;
    bool changed_;
};

// Find the batch containing query q from a prefix-sum pointer, via binary
// search. Returns the batch id in [0, batch_size).
int64_t BatchOf(int64_t q, const int64_t* ptr_y, int64_t batch_size) {
    int64_t low = 0;
    int64_t high = batch_size;
    while (low < high) {
        int64_t mid = (low + high) >> 1;
        if (ptr_y[mid + 1] <= q) {
            low = mid + 1;
        } else {
            high = mid;
        }
    }
    return low;
}

// Scan one query's batch on CPU, appending in-radius neighbors (in x-index
// ascending order) to row0/row1, up to max_neighbors.
void ScanQueryCpu(int64_t q, int64_t x_start, int64_t x_end,
                  const double* x_ptr, const double* y_ptr,
                  int64_t feature_dim, double r2, int64_t max_neighbors,
                  bool ignore_same_index, std::vector<int64_t>& row0,
                  std::vector<int64_t>& row1) {
    int64_t kept = 0;
    for (int64_t i = x_start; i < x_end; ++i) {
        if (ignore_same_index && i == q) {
            continue;
        }
        double dist2 = 0.0;
        for (int64_t d = 0; d < feature_dim; ++d) {
            double diff = x_ptr[i * feature_dim + d] - y_ptr[q * feature_dim + d];
            dist2 += diff * diff;
        }
        if (dist2 > r2) {
            continue;
        }
        if (kept < max_neighbors) {
            row0.push_back(q);
            row1.push_back(i);
            ++kept;
        }
    }
}

// Scalar CPU reference for the float64 fallback (no NPU kernel path). Mirrors
// torch_cluster.radius: for each query q, scan its batch for points within r
// in x-index ascending order, keeping at most max_neighbors.
torch::Tensor RadiusCpuFallback(torch::Tensor x, torch::Tensor y,
                                const torch::Tensor& ptr_x_cpu,
                                const torch::Tensor& ptr_y_cpu,
                                int64_t batch_size, double r, int64_t max_neighbors,
                                bool ignore_same_index) {
    auto x_cpu = x.cpu().contiguous().to(torch::kDouble);
    auto y_cpu = y.cpu().contiguous().to(torch::kDouble);
    const int64_t n = x_cpu.size(0);
    const int64_t m = y_cpu.size(0);
    const int64_t feature_dim = x_cpu.size(1);
    const double* x_ptr = x_cpu.data_ptr<double>();
    const double* y_ptr = y_cpu.data_ptr<double>();
    const int64_t* ptr_x = batch_size > 1 ? ptr_x_cpu.data_ptr<int64_t>() : nullptr;
    const int64_t* ptr_y = batch_size > 1 ? ptr_y_cpu.data_ptr<int64_t>() : nullptr;
    const double r2 = r * r;

    std::vector<int64_t> row0;
    std::vector<int64_t> row1;
    row0.reserve(static_cast<size_t>(n));
    row1.reserve(static_cast<size_t>(n));

    for (int64_t q = 0; q < m; ++q) {
        int64_t batch = (batch_size > 1) ? BatchOf(q, ptr_y, batch_size) : 0;
        int64_t x_start = 0;
        int64_t x_end = n;
        if (batch_size > 1) {
            x_start = ptr_x[batch];
            x_end = ptr_x[batch + 1];
        }
        ScanQueryCpu(q, x_start, x_end, x_ptr, y_ptr, feature_dim, r2,
                     max_neighbors, ignore_same_index, row0, row1);
    }

    const int64_t e = static_cast<int64_t>(row0.size());
    auto row0_tensor =
        torch::from_blob(row0.data(), {e},
                         torch::TensorOptions().dtype(torch::kLong))
            .clone();
    auto row1_tensor =
        torch::from_blob(row1.data(), {e},
                         torch::TensorOptions().dtype(torch::kLong))
            .clone();
    return torch::stack({row0_tensor, row1_tensor}, 0).to(x.device());
}

struct BatchContext {
    torch::Tensor ptr_x_npu;
    torch::Tensor ptr_y_npu;
    torch::Tensor ptr_x_cpu;
    torch::Tensor ptr_y_cpu;
    int64_t batch_size = 1;
    bool has_batch = false;
};

// A prefix-sum batch pointer must start at 0, end at the data length, stay
// non-decreasing and never leave [0, data_len]; otherwise the kernel can
// dereference out-of-range GM addresses.
void ValidatePtr(const torch::Tensor& ptr, int64_t data_len, const char* name) {
    const int64_t* p = ptr.data_ptr<int64_t>();
    const int64_t numel = ptr.numel();
    TORCH_CHECK(numel >= 2, "radius_npu: ", name, " must contain at least 2 elements");
    TORCH_CHECK(p[0] == 0, "radius_npu: ", name, " must start with 0");
    TORCH_CHECK(p[numel - 1] == data_len,
                "radius_npu: ", name, " must end with the data length");
    for (int64_t i = 0; i < numel; ++i) {
        TORCH_CHECK(p[i] >= 0 && p[i] <= data_len,
                    "radius_npu: ", name, " value out of range");
        if (i > 0) {
            TORCH_CHECK(p[i - 1] <= p[i],
                        "radius_npu: ", name, " must be non-decreasing");
        }
    }
}

// Validate inputs, resolve the batch pointer arguments and compute the batch
// context. Returns empty BatchContext when no batch is present.
BatchContext ResolveBatch(torch::Tensor& x, torch::Tensor& y,
                          const std::optional<torch::Tensor>& ptr_x,
                          const std::optional<torch::Tensor>& ptr_y) {
    TORCH_CHECK(x.device() == y.device(), "radius_npu: x and y must be on the same device");
    TORCH_CHECK(!x.is_cpu() && !y.is_cpu(), "radius_npu: x and y must be NPU tensors");
    TORCH_CHECK(x.dim() == 2 && y.dim() == 2, "radius_npu: x and y must be 2D tensors");
    TORCH_CHECK(x.size(1) == y.size(1), "radius_npu: x and y feature dims must match");
    TORCH_CHECK(x.scalar_type() == y.scalar_type(), "radius_npu: x and y dtypes must match");

    BatchContext ctx;
    bool present = ptr_x.has_value() && ptr_x->defined() &&
                   ptr_y.has_value() && ptr_y->defined();
    if (!present) {
        return ctx;
    }
    // A CPU pointer must never be handed to the NPU kernel directly, so
    // require both pointers on the same device as the data.
    TORCH_CHECK(ptr_x->device() == x.device(),
                "radius_npu: ptr_x must be on the same device as x");
    TORCH_CHECK(ptr_y->device() == y.device(),
                "radius_npu: ptr_y must be on the same device as y");
    ctx.ptr_x_npu = ptr_x->contiguous();
    ctx.ptr_y_npu = ptr_y->contiguous();
    TORCH_CHECK(ctx.ptr_x_npu.scalar_type() == torch::kLong,
                "radius_npu: ptr_x must be int64");
    TORCH_CHECK(ctx.ptr_y_npu.scalar_type() == torch::kLong,
                "radius_npu: ptr_y must be int64");
    TORCH_CHECK(ctx.ptr_x_npu.dim() == 1 && ctx.ptr_y_npu.dim() == 1,
                "radius_npu: ptr_x and ptr_y must be 1D");
    TORCH_CHECK(ctx.ptr_x_npu.numel() == ctx.ptr_y_npu.numel(),
                "radius_npu: ptr_x and ptr_y sizes must match");
    ctx.batch_size = ctx.ptr_x_npu.numel() - 1;
    TORCH_CHECK(ctx.batch_size > 0, "radius_npu: batch_size must be positive");
    ctx.ptr_x_cpu = ctx.ptr_x_npu.cpu().contiguous();
    ctx.ptr_y_cpu = ctx.ptr_y_npu.cpu().contiguous();
    ValidatePtr(ctx.ptr_x_cpu, x.size(0), "ptr_x");
    ValidatePtr(ctx.ptr_y_cpu, y.size(0), "ptr_y");
    ctx.has_batch = ctx.batch_size > 1;
    return ctx;
}

// Build the spatial grid. The single-batch fast path builds on-device; the
// batched path builds on CPU with the intra-op thread pool capped to the
// container's CPU quota (prevents cgroup CFS throttling at N>=32K).
GridHostData BuildGridScoped(const torch::Tensor& x, const BatchContext& ctx,
                             double r, int64_t n, int64_t m, int64_t feature_dim,
                             int64_t max_num_neighbors) {
    int32_t cap = NumThreadsCap();
    NumThreadsGuard thread_guard(cap);
    GridHostData grid;
    if (ctx.batch_size == 1) {
        grid = BuildGridDevice(x, r, n, m, feature_dim, max_num_neighbors);
        aclError sync_ret = aclrtSynchronizeDevice();
        TORCH_CHECK(sync_ret == ACL_SUCCESS,
                    "radius_npu: device-grid-build sync failed: ", sync_ret);
    } else {
        torch::Tensor x_cpu = x.cpu().contiguous();
        grid = BuildGrid(x_cpu, ctx.ptr_x_cpu, ctx.batch_size, r, n, m,
                         feature_dim, max_num_neighbors);
    }
    return grid;
}

struct LaunchBundle {
    torch::Tensor counts;
    torch::Tensor out_row0;
    torch::Tensor out_row1;
    torch::Tensor offsets_npu;
    torch::Tensor reordered_npu;
    torch::Tensor orig_npu;
    torch::Tensor config_npu;
    torch::Tensor tiling_npu;
    aclrtStream stream;
};

// Build the scalar tiling struct and upload it to the device. Tiling travels
// through GM as raw bytes; structs are never staged by value through the SIMT
// launch path (see radius_kernel.cpp).
torch::Tensor BuildTilingDevice(const torch::Tensor& x, const BatchContext& ctx,
                                const GridHostData& grid, double r, int64_t n,
                                int64_t m, int64_t feature_dim,
                                int64_t max_num_neighbors,
                                bool ignore_same_index) {
    auto ascendcPlatform = platform_ascendc::PlatformAscendCManager::GetInstance();
    uint32_t core_num = ascendcPlatform->GetCoreNumAiv();
    if (core_num == 0) {
        core_num = 1;
    }
    RadiusTilingData tiling{};
    tiling.n = n;
    tiling.m = m;
    tiling.feature_dim = feature_dim;
    tiling.batch_size = ctx.batch_size;
    tiling.max_num_neighbors = max_num_neighbors;
    tiling.r2 = static_cast<float>(r * r);
    tiling.ignore_same_index = ignore_same_index ? 1 : 0;
    tiling.core_num = static_cast<int64_t>(core_num);
    tiling.workspace_pairs = m * max_num_neighbors;
    tiling.use_grid = grid.use_grid ? 1 : 0;
    tiling.unique_cells = grid.grid_cell_count;  // dense offset stride
    tiling.config_ptr = 0;

    auto tiling_cpu =
        torch::from_blob(&tiling,
                         {static_cast<int64_t>(sizeof(RadiusTilingData))},
                         torch::TensorOptions().dtype(torch::kUInt8))
            .clone();
    return tiling_cpu.to(x.device());
}

// Upload the grid metadata (offsets, reordered x/orig idx, config) to device.
void UploadGrid(const torch::Tensor& x, const BatchContext& ctx,
                const GridHostData& grid, LaunchBundle& b) {
    b.offsets_npu = grid.cell_offsets.to(x.device());
    if (ctx.batch_size == 1) {
        // Device grid build already produced NPU tensors.
        b.reordered_npu = grid.reordered_x;
        b.orig_npu = grid.reordered_orig_idx;
    } else {
        b.reordered_npu = grid.reordered_x.to(x.device());
        b.orig_npu = grid.reordered_orig_idx.to(x.device());
    }
    RadiusGridConfig config_copy = grid.config;
    auto config_cpu =
        torch::from_blob(&config_copy,
                         {static_cast<int64_t>(sizeof(RadiusGridConfig))},
                         torch::TensorOptions().dtype(torch::kUInt8))
            .clone();
    b.config_npu = config_cpu.to(x.device());
}

// Allocate the dense m*K output buffers on the device.
void AllocateBuffers(const torch::Tensor& x, int64_t m,
                     int64_t max_num_neighbors, LaunchBundle& b) {
    auto long_opts = torch::TensorOptions().dtype(torch::kLong).device(x.device());
    b.counts = torch::zeros({m}, long_opts);
    b.out_row0 = torch::empty({m * max_num_neighbors}, long_opts);
    b.out_row1 = torch::empty({m * max_num_neighbors}, long_opts);
}

// Resolve the launch stream: prefer the torch framework's current stream
// (passed from Python via torch.npu.current_stream()), so all prior device
// work is naturally ordered before the kernel without a device-wide barrier.
aclrtStream ResolveStream(int64_t stream_handle) {
    aclrtStream stream = reinterpret_cast<aclrtStream>(stream_handle);
    if (stream == nullptr) {
        static aclrtStream fallback_stream = []() {
            aclrtStream s = nullptr;
            aclError r = aclrtCreateStream(&s);
            TORCH_CHECK(r == ACL_SUCCESS,
                        "radius_npu: static aclrtCreateStream failed: ", r);
            return s;
        }();
        stream = fallback_stream;
        aclError sync_ret = aclrtSynchronizeDevice();
        TORCH_CHECK(sync_ret == ACL_SUCCESS,
                    "radius_npu: pre-launch device sync failed: ", sync_ret);
    }
    return stream;
}

// Fill the scalar tiling struct, upload it (and the grid metadata) to the
// device, and allocate the dense m*K output buffers.
LaunchBundle PrepareLaunch(const torch::Tensor& x, const BatchContext& ctx,
                           const GridHostData& grid, double r, int64_t n,
                           int64_t m, int64_t feature_dim,
                           int64_t max_num_neighbors, bool ignore_same_index,
                           int64_t stream_handle) {
    LaunchBundle b;
    AllocateBuffers(x, m, max_num_neighbors, b);
    if (grid.use_grid) {
        UploadGrid(x, ctx, grid, b);
    }
    b.tiling_npu =
        BuildTilingDevice(x, ctx, grid, r, n, m, feature_dim,
                          max_num_neighbors, ignore_same_index);
    b.stream = ResolveStream(stream_handle);
    return b;
}

template <typename T, int DType>
void LaunchDispatch(const torch::Tensor& x, const torch::Tensor& y,
                    const BatchContext& ctx, const GridHostData& grid,
                    const LaunchBundle& b) {
    RadiusLaunchArgs<T> args;
    args.ptr_x = ctx.has_batch ? ctx.ptr_x_npu.data_ptr<int64_t>() : nullptr;
    args.ptr_y = ctx.has_batch ? ctx.ptr_y_npu.data_ptr<int64_t>() : nullptr;
    args.unique_cell_ids = nullptr;
    args.cell_offsets =
        grid.use_grid ? b.offsets_npu.data_ptr<int64_t>() : nullptr;
    args.reordered_x =
        grid.use_grid ? static_cast<T*>(b.reordered_npu.data_ptr()) : nullptr;
    args.reordered_orig_idx =
        grid.use_grid ? b.orig_npu.data_ptr<int64_t>() : nullptr;
    args.counts = b.counts.data_ptr<int64_t>();
    args.out_row0 = b.out_row0.data_ptr<int64_t>();
    args.out_row1 = b.out_row1.data_ptr<int64_t>();
    args.config_ptr = grid.use_grid ? b.config_npu.data_ptr<uint8_t>() : nullptr;
    args.tiling_gm = b.tiling_npu.data_ptr<uint8_t>();
    LaunchRadiusKernel<T, DType>(static_cast<T*>(x.data_ptr()),
                                 static_cast<T*>(y.data_ptr()), args, b.stream);
}

// Compact the dense m*K buffers into [2, E] on the device, then D2H-copy only
// the compressed result. row0[q*K+p] is always q, so it is rebuilt from counts
// with repeat_interleave; out_row1 is compressed with masked_select. Both ops
// run on the NPU.
torch::Tensor CompactResult(const torch::Tensor& x, const LaunchBundle& b,
                            int64_t m, int64_t max_num_neighbors) {
    const int64_t e = b.counts.sum().item<int64_t>();
    if (e == 0) {
        return torch::stack(
                   {torch::empty({0}, torch::TensorOptions().dtype(torch::kLong)),
                    torch::empty({0}, torch::TensorOptions().dtype(torch::kLong))},
                   0)
            .to(x.device());
    }
    auto long_dev = torch::TensorOptions().dtype(torch::kLong).device(x.device());
    auto arange_k = torch::arange(max_num_neighbors, long_dev);
    // mask = (arange_k[None, :] < counts[:, None]) flattened; [m*K] bool.
    auto mask_t =
        arange_k.unsqueeze(0)
            .expand({m, max_num_neighbors})
            .lt(b.counts.unsqueeze(1).expand({m, max_num_neighbors}))
            .reshape({-1});
    auto compact1 = b.out_row1.masked_select(mask_t);
    auto compact0 = torch::arange(m, long_dev).repeat_interleave(b.counts);
    // The grid-path kernel k-way merges neighbor cells in ascending x-index
    // order, so compact0/compact1 are already in the exact order the CPU
    // reference produces (matches official test_radius.py torch.equal).
    return torch::stack({compact0, compact1}, 0).cpu().to(x.device());
}

}  // namespace

torch::Tensor radius_npu(
    torch::Tensor x,
    torch::Tensor y,
    std::optional<torch::Tensor> ptr_x,
    std::optional<torch::Tensor> ptr_y,
    double r,
    int64_t max_num_neighbors,
    int64_t num_workers,
    bool ignore_same_index,
    int64_t stream_handle) {
    (void)num_workers;
    // The kernel reads GM as contiguous 2D rows; make the public entry robust
    // to non-contiguous inputs even when called below the Python wrapper.
    x = x.contiguous();
    y = y.contiguous();
    TORCH_CHECK(x.device() == y.device(),
                "radius_npu: x and y must be on the same device");
    TORCH_CHECK(!x.is_cpu() && !y.is_cpu(),
                "radius_npu: x and y must be NPU tensors");
    const int64_t n = x.size(0);
    const int64_t m = y.size(0);
    const int64_t feature_dim = x.size(1);
    if (n == 0 || m == 0 || !(r > 0.0) || max_num_neighbors <= 0) {
        return EmptyEdgeIndex(x);
    }

    BatchContext ctx = ResolveBatch(x, y, ptr_x, ptr_y);

    const auto dtype = x.scalar_type();
    if (dtype == torch::kDouble) {
        return RadiusCpuFallback(x, y, ctx.ptr_x_cpu, ctx.ptr_y_cpu,
                                 ctx.batch_size, r, max_num_neighbors,
                                 ignore_same_index);
    }
    TORCH_CHECK(dtype == torch::kFloat || dtype == torch::kHalf ||
                    dtype == torch::kBFloat16,
                "radius_npu: supported dtypes are float16, bfloat16, float32, float64");

    GridHostData grid =
        BuildGridScoped(x, ctx, r, n, m, feature_dim, max_num_neighbors);
    LaunchBundle bundle =
        PrepareLaunch(x, ctx, grid, r, n, m, feature_dim, max_num_neighbors,
                      ignore_same_index, stream_handle);

    if (dtype == torch::kFloat) {
        LaunchDispatch<float, 0>(x, y, ctx, grid, bundle);
    } else if (dtype == torch::kHalf) {
        LaunchDispatch<uint16_t, 1>(x, y, ctx, grid, bundle);
    } else {
        LaunchDispatch<uint16_t, 2>(x, y, ctx, grid, bundle);
    }

    aclError acl_ret = aclrtGetLastError(ACL_RT_THREAD_LEVEL);
    TORCH_CHECK(acl_ret == ACL_SUCCESS,
                "radius_npu: kernel launch failed: ", acl_ret);
    acl_ret = aclrtSynchronizeStream(bundle.stream);
    TORCH_CHECK(acl_ret == ACL_SUCCESS,
                "radius_npu: stream sync failed (device fault): ", acl_ret);

    return CompactResult(x, bundle, m, max_num_neighbors);
}
