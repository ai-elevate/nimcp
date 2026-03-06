/**
 * @file nimcp_sparse_kernels.cu
 * @brief GPU Sparse Tensor CUDA Kernels Implementation with cuSPARSE
 *
 * WHAT: CUDA kernels and cuSPARSE wrappers for sparse tensor operations
 * WHY:  GPU acceleration for sparse neural network computations
 * HOW:  cuSPARSE for SpMM/SpMV, custom kernels for pruning and masking
 *
 * RNG USAGE:
 * ==========
 * Uses inline curand_init for stochastic sparse tensor initialization.
 * For general GPU statistics RNG, see: gpu/statistics/nimcp_statistics_gpu.h
 * For shared device RNG functions, see: gpu/common/nimcp_device_utils.cuh
 *
 * @version 1.0
 * @author NIMCP Development Team
 * @date 2025
 */

#ifdef NIMCP_ENABLE_CUDA

// Include CUDA headers FIRST (before any extern "C" blocks from our headers)
#include <cuda_runtime.h>
#include <cusparse.h>
#include <cublas_v2.h>
#include <curand.h>
#include <curand_kernel.h>
#include <math.h>
#include <float.h>
#include <algorithm>
#include <thrust/device_ptr.h>
#include <thrust/sort.h>
#include <thrust/scan.h>
#include <thrust/reduce.h>
#include <thrust/count.h>
#include <thrust/sequence.h>
#include <thrust/execution_policy.h>

// Now include our headers (which have extern "C" blocks)
#include "gpu/sparse/nimcp_sparse_gpu.h"
#include "gpu/recovery/nimcp_gpu_recovery.h"
#include "utils/logging/nimcp_logging.h"
#include "utils/exception/nimcp_exception_macros.h"
#include "gpu/common/nimcp_cuda_utils.h"
#include "utils/memory/nimcp_memory.h"

#define LOG_MODULE "SPARSE_GPU"

#define CUSPARSE_CHECK(call) do { \
    cusparseStatus_t status = call; \
    if (status != CUSPARSE_STATUS_SUCCESS) { \
        LOG_ERROR("cuSPARSE error at %s:%d: %d", __FILE__, __LINE__, status); \
        return false; \
    } \
} while(0)

#define CUSPARSE_CHECK_PTR(call) do { \
    cusparseStatus_t status = call; \
    if (status != CUSPARSE_STATUS_SUCCESS) { \
        LOG_ERROR("cuSPARSE error at %s:%d: %d", __FILE__, __LINE__, status); \
        return NULL; \
    } \
} while(0)

//=============================================================================
// Kernel Configuration
//=============================================================================

#define BLOCK_SIZE 256
#define WARP_SIZE 32
#define GRID_SIZE(n) (((n) + BLOCK_SIZE - 1) / BLOCK_SIZE)

//=============================================================================
// Context Lifecycle Implementation
//=============================================================================

nimcp_sparse_ctx_t* nimcp_sparse_ctx_create(nimcp_gpu_context_t* gpu_ctx)
{
    if (!nimcp_gpu_recovery_is_initialized()) {
        nimcp_gpu_recovery_init(NULL);
    }

    if (!gpu_ctx) {
        LOG_ERROR("NULL GPU context provided");
        return NULL;
    }

    nimcp_sparse_ctx_t* ctx = (nimcp_sparse_ctx_t*)nimcp_calloc(1, sizeof(nimcp_sparse_ctx_t));
    if (!ctx) {
        LOG_ERROR("Failed to allocate sparse context");
        return NULL;
    }

    ctx->gpu_ctx = gpu_ctx;
    ctx->workspace = NULL;
    ctx->workspace_size = 0;
    ctx->workspace_capacity = 0;

    // Create cuSPARSE handle
    cusparseStatus_t status = cusparseCreate(&ctx->cusparse_handle);
    if (status != CUSPARSE_STATUS_SUCCESS) {
        LOG_ERROR("Failed to create cuSPARSE handle: %d", status);
        nimcp_free(ctx);
        return NULL;
    }

    // Set stream to GPU context's compute stream
    status = cusparseSetStream(ctx->cusparse_handle, gpu_ctx->compute_stream);
    if (status != CUSPARSE_STATUS_SUCCESS) {
        LOG_WARN("Failed to set cuSPARSE stream: %d", status);
    }

    // Allocate initial workspace (1MB)
    size_t initial_workspace = 1024 * 1024;
    cudaError_t err = cudaMalloc(&ctx->workspace, initial_workspace);
    if (err == cudaSuccess) {
        ctx->workspace_capacity = initial_workspace;
    } else {
        LOG_WARN("Failed to allocate initial sparse workspace");
    }

    LOG_DEBUG("Created sparse context with cuSPARSE handle");
    return ctx;
}

void nimcp_sparse_ctx_destroy(nimcp_sparse_ctx_t* ctx)
{
    if (!ctx) return;

    if (ctx->cusparse_handle) {
        cusparseDestroy(ctx->cusparse_handle);
    }

    if (ctx->workspace) {
        cudaFree(ctx->workspace);
    }

    nimcp_free(ctx);
    LOG_DEBUG("Destroyed sparse context");
}

bool nimcp_sparse_ctx_ensure_workspace(nimcp_sparse_ctx_t* ctx, size_t required_size)
{
    if (!ctx) return false;

    if (ctx->workspace_capacity >= required_size) {
        ctx->workspace_size = required_size;
        return true;
    }

    // Grow workspace (with some headroom)
    size_t new_capacity = required_size + required_size / 4;  // 25% extra

    if (ctx->workspace) {
        cudaFree(ctx->workspace);
        ctx->workspace = NULL;
    }

    cudaError_t err = cudaMalloc(&ctx->workspace, new_capacity);
    if (err != cudaSuccess) {
        LOG_ERROR("Failed to allocate workspace of %zu bytes", new_capacity);
        ctx->workspace_capacity = 0;
        ctx->workspace_size = 0;
        return false;
    }

    ctx->workspace_capacity = new_capacity;
    ctx->workspace_size = required_size;
    LOG_DEBUG("Allocated sparse workspace: %zu bytes", new_capacity);
    return true;
}

//=============================================================================
// Custom CUDA Kernels
//=============================================================================

/**
 * @brief Count non-zeros above threshold
 */
__global__ void kernel_count_nonzeros(
    const float* dense,
    int* nnz_count,
    float threshold,
    int n)
{
    __shared__ int block_count;
    if (threadIdx.x == 0) block_count = 0;
    __syncthreads();

    int thread_count = 0;
    for (int idx = blockIdx.x * blockDim.x + threadIdx.x; idx < n; idx += blockDim.x * gridDim.x) {
        if (fabsf(dense[idx]) >= threshold) {
            thread_count++;
        }
    }

    // Reduce within block
    atomicAdd(&block_count, thread_count);
    __syncthreads();

    // First thread adds to global
    if (threadIdx.x == 0) {
        atomicAdd(nnz_count, block_count);
    }
}

/**
 * @brief Extract COO indices from dense tensor
 */
__global__ void kernel_dense_to_coo(
    const float* dense,
    float* values,
    int* row_indices,
    int* col_indices,
    int* nnz_counter,
    float threshold,
    int rows,
    int cols)
{
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    int total = rows * cols;

    if (idx < total) {
        float val = dense[idx];
        if (fabsf(val) >= threshold) {
            int pos = atomicAdd(nnz_counter, 1);
            values[pos] = val;
            row_indices[pos] = idx / cols;
            col_indices[pos] = idx % cols;
        }
    }
}

/**
 * @brief Convert COO to CSR row pointers
 */
__global__ void kernel_coo_to_csr_row_ptrs(
    const int* row_indices,
    int* row_ptrs,
    int nnz,
    int rows)
{
    // Initialize row_ptrs to 0
    for (int i = threadIdx.x; i <= rows; i += blockDim.x) {
        row_ptrs[i] = 0;
    }
    __syncthreads();

    // Count elements per row
    for (int i = blockIdx.x * blockDim.x + threadIdx.x; i < nnz; i += blockDim.x * gridDim.x) {
        atomicAdd(&row_ptrs[row_indices[i] + 1], 1);
    }
    __syncthreads();

    // Inclusive scan (prefix sum) - simple serial version for small row counts
    if (threadIdx.x == 0 && blockIdx.x == 0) {
        for (int i = 1; i <= rows; i++) {
            row_ptrs[i] += row_ptrs[i - 1];
        }
    }
}

/**
 * @brief Apply sparse mask to dense tensor
 */
__global__ void kernel_apply_sparse_mask_csr(
    const float* dense_in,
    float* dense_out,
    const int* row_ptrs,
    const int* col_indices,
    int rows,
    int cols)
{
    int row = blockIdx.x;
    if (row >= rows) return;

    int row_start = row_ptrs[row];
    int row_end = row_ptrs[row + 1];

    // First, zero the entire row in output
    for (int col = threadIdx.x; col < cols; col += blockDim.x) {
        dense_out[row * cols + col] = 0.0f;
    }
    __syncthreads();

    // Then copy only masked positions
    for (int j = row_start + threadIdx.x; j < row_end; j += blockDim.x) {
        int col = col_indices[j];
        dense_out[row * cols + col] = dense_in[row * cols + col];
    }
}

/**
 * @brief Accumulate sparse gradients into dense tensor
 */
__global__ void kernel_sparse_grad_accumulate_csr(
    const float* sparse_values,
    const int* row_ptrs,
    const int* col_indices,
    float* dense_grad,
    int rows,
    int cols)
{
    int row = blockIdx.x;
    if (row >= rows) return;

    int row_start = row_ptrs[row];
    int row_end = row_ptrs[row + 1];

    for (int j = row_start + threadIdx.x; j < row_end; j += blockDim.x) {
        int col = col_indices[j];
        atomicAdd(&dense_grad[row * cols + col], sparse_values[j]);
    }
}

/**
 * @brief Scale sparse values in-place
 */
__global__ void kernel_sparse_scale(float* values, float scale, int nnz)
{
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    if (idx < nnz) {
        values[idx] *= scale;
    }
}

/**
 * @brief Sparse to dense conversion (CSR)
 */
__global__ void kernel_csr_to_dense(
    const float* values,
    const int* col_indices,
    const int* row_ptrs,
    float* dense,
    int rows,
    int cols)
{
    int row = blockIdx.x;
    if (row >= rows) return;

    // Zero the row first
    for (int col = threadIdx.x; col < cols; col += blockDim.x) {
        dense[row * cols + col] = 0.0f;
    }
    __syncthreads();

    // Fill in non-zeros
    int row_start = row_ptrs[row];
    int row_end = row_ptrs[row + 1];
    for (int j = row_start + threadIdx.x; j < row_end; j += blockDim.x) {
        dense[row * cols + col_indices[j]] = values[j];
    }
}

/**
 * @brief Find threshold for target sparsity using histogram
 */
__global__ void kernel_magnitude_histogram(
    const float* data,
    int* histogram,
    int n,
    float max_val,
    int num_bins)
{
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    if (idx < n) {
        float abs_val = fabsf(data[idx]);
        int bin = (int)((abs_val / max_val) * (num_bins - 1));
        bin = min(bin, num_bins - 1);
        atomicAdd(&histogram[bin], 1);
    }
}

/**
 * @brief Sparse attention kernel (simplified for demonstration)
 */
__global__ void kernel_sparse_attention(
    const float* Q,       // [batch, heads, seq, head_dim]
    const float* K,       // [batch, heads, seq, head_dim]
    const float* V,       // [batch, heads, seq, head_dim]
    const int* mask_row_ptrs,
    const int* mask_col_indices,
    float* output,        // [batch, heads, seq, head_dim]
    int batch,
    int heads,
    int seq_len,
    int head_dim)
{
    int batch_idx = blockIdx.z;
    int head_idx = blockIdx.y;
    int seq_idx = blockIdx.x;

    if (batch_idx >= batch || head_idx >= heads || seq_idx >= seq_len) return;

    extern __shared__ float shared_mem[];

    int qkv_offset = ((batch_idx * heads + head_idx) * seq_len + seq_idx) * head_dim;

    // Load Q for this position
    float q_val[64];  // Assume head_dim <= 64
    for (int d = 0; d < head_dim; d++) {
        q_val[d] = Q[qkv_offset + d];
    }

    // Get attention mask range for this row
    int mask_start = mask_row_ptrs[seq_idx];
    int mask_end = mask_row_ptrs[seq_idx + 1];

    // Compute attention scores only for non-masked positions
    float max_score = -FLT_MAX;
    float scores[128];  // Assume max nnz per row <= 128
    int num_scores = mask_end - mask_start;

    for (int m = 0; m < num_scores; m++) {
        int key_idx = mask_col_indices[mask_start + m];
        int k_offset = ((batch_idx * heads + head_idx) * seq_len + key_idx) * head_dim;

        float score = 0.0f;
        for (int d = 0; d < head_dim; d++) {
            score += q_val[d] * K[k_offset + d];
        }
        score /= sqrtf((float)head_dim);
        scores[m] = score;
        max_score = fmaxf(max_score, score);
    }

    // Softmax
    float sum_exp = 0.0f;
    for (int m = 0; m < num_scores; m++) {
        scores[m] = expf(scores[m] - max_score);
        sum_exp += scores[m];
    }
    for (int m = 0; m < num_scores; m++) {
        scores[m] /= sum_exp;
    }

    // Weighted sum of values
    float out_val[64] = {0};
    for (int m = 0; m < num_scores; m++) {
        int val_idx = mask_col_indices[mask_start + m];
        int v_offset = ((batch_idx * heads + head_idx) * seq_len + val_idx) * head_dim;
        for (int d = 0; d < head_dim; d++) {
            out_val[d] += scores[m] * V[v_offset + d];
        }
    }

    // Write output
    for (int d = threadIdx.x; d < head_dim; d += blockDim.x) {
        output[qkv_offset + d] = out_val[d];
    }
}

/**
 * @brief Structured N:M pruning kernel
 */
__global__ void kernel_structured_prune(
    const float* input,
    float* output,
    int* mask,  // 1 where kept, 0 where pruned
    int N,      // Keep N values
    int M,      // Per M elements
    int total_elements)
{
    int group_idx = blockIdx.x * blockDim.x + threadIdx.x;
    int num_groups = (total_elements + M - 1) / M;

    if (group_idx >= num_groups) return;

    int start = group_idx * M;
    int end = min(start + M, total_elements);
    int group_size = end - start;

    // Load group values and their indices
    float abs_vals[16];  // M <= 16
    int indices[16];
    for (int i = 0; i < group_size; i++) {
        abs_vals[i] = fabsf(input[start + i]);
        indices[i] = i;
    }

    // Simple selection sort to find top-N (for small M)
    for (int i = 0; i < min(N, group_size); i++) {
        int max_idx = i;
        for (int j = i + 1; j < group_size; j++) {
            if (abs_vals[j] > abs_vals[max_idx]) {
                max_idx = j;
            }
        }
        // Swap
        float tmp_val = abs_vals[i];
        abs_vals[i] = abs_vals[max_idx];
        abs_vals[max_idx] = tmp_val;

        int tmp_idx = indices[i];
        indices[i] = indices[max_idx];
        indices[max_idx] = tmp_idx;
    }

    // Write output: keep top N, zero others
    for (int i = 0; i < group_size; i++) {
        bool keep = false;
        for (int j = 0; j < min(N, group_size); j++) {
            if (indices[j] == i) {
                keep = true;
                break;
            }
        }
        output[start + i] = keep ? input[start + i] : 0.0f;
        if (mask) mask[start + i] = keep ? 1 : 0;
    }
}

/**
 * @brief Random sparse pattern generation
 */
__global__ void kernel_random_sparse_coo(
    float* values,
    int* row_indices,
    int* col_indices,
    int rows,
    int cols,
    int nnz,
    unsigned long long seed)
{
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    if (idx >= nnz) return;

    // Initialize curand state
    curandState state;
    curand_init(seed, idx, 0, &state);

    // Random position
    int total = rows * cols;
    int pos = curand(&state) % total;
    row_indices[idx] = pos / cols;
    col_indices[idx] = pos % cols;

    // Random value in [-1, 1]
    values[idx] = curand_uniform(&state) * 2.0f - 1.0f;
}

//=============================================================================
// Helper Functions
//=============================================================================

/**
 * @brief Get sparse tensor dimensions
 */
static void get_sparse_dims(const nimcp_sparse_tensor_t* tensor, int* rows, int* cols, int* nnz)
{
    switch (tensor->format) {
        case SPARSE_FORMAT_CSR:
            *rows = tensor->data.csr.rows;
            *cols = tensor->data.csr.cols;
            *nnz = tensor->data.csr.nnz;
            break;
        case SPARSE_FORMAT_CSC:
            *rows = tensor->data.csc.rows;
            *cols = tensor->data.csc.cols;
            *nnz = tensor->data.csc.nnz;
            break;
        case SPARSE_FORMAT_COO:
            *rows = tensor->data.coo.rows;
            *cols = tensor->data.coo.cols;
            *nnz = tensor->data.coo.nnz;
            break;
        case SPARSE_FORMAT_BSR:
            *rows = tensor->data.bsr.rows * tensor->data.bsr.block_size;
            *cols = tensor->data.bsr.cols * tensor->data.bsr.block_size;
            *nnz = tensor->data.bsr.nnz_blocks * tensor->data.bsr.block_size * tensor->data.bsr.block_size;
            break;
        case SPARSE_FORMAT_ELL:
            *rows = tensor->data.ell.rows;
            *cols = tensor->data.ell.cols;
            *nnz = tensor->data.ell.nnz;
            break;
        default:
            *rows = 0;
            *cols = 0;
            *nnz = 0;
    }
}

//=============================================================================
// Sparse Tensor Creation Implementation
//=============================================================================

nimcp_sparse_tensor_t* nimcp_sparse_from_dense(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* dense,
    nimcp_sparse_format_t format,
    float threshold)
{
    if (!nimcp_gpu_recovery_is_initialized()) {
        nimcp_gpu_recovery_init(NULL);
    }

    if (!ctx || !dense) {
        LOG_ERROR("Invalid parameters for sparse_from_dense");
        return NULL;
    }

    if (dense->ndim != 2) {
        LOG_ERROR("sparse_from_dense requires 2D tensor, got %u dims", dense->ndim);
        return NULL;
    }

    int rows = dense->dims[0];
    int cols = dense->dims[1];
    int total = rows * cols;

    // Count non-zeros
    int* d_nnz_count;
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_nnz_count, sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMemset(d_nnz_count, 0, sizeof(int)), GPU_ERROR_CUDA_RUNTIME);

    int grid = GRID_SIZE(total);
    grid = min(grid, 256);
    kernel_count_nonzeros<<<grid, BLOCK_SIZE>>>(
        (const float*)dense->data, d_nnz_count, threshold, total);

    int nnz;
    NIMCP_CUDA_RECOVER_NULL(cudaMemcpy(&nnz, d_nnz_count, sizeof(int), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);
    cudaFree(d_nnz_count);

    if (nnz == 0) {
        LOG_WARN("No non-zeros found with threshold %f", threshold);
        return NULL;
    }

    LOG_DEBUG("Converting dense %dx%d to sparse: %d non-zeros (%.1f%% sparsity)",
              rows, cols, nnz, 100.0f * (1.0f - (float)nnz / total));

    // Allocate sparse tensor
    nimcp_sparse_tensor_t* sparse = (nimcp_sparse_tensor_t*)nimcp_calloc(1, sizeof(nimcp_sparse_tensor_t));
    if (!sparse) return NULL;

    sparse->format = format;
    sparse->on_device = true;
    sparse->ctx = ctx->gpu_ctx;
    sparse->owns_data = true;

    // Allocate COO arrays
    float* d_values;
    int* d_row_indices;
    int* d_col_indices;
    int* d_nnz_counter;

    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_values, nnz * sizeof(float)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_row_indices, nnz * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_col_indices, nnz * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_nnz_counter, sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);
    cudaMemset(d_nnz_counter, 0, sizeof(int));

    // Extract COO data
    kernel_dense_to_coo<<<GRID_SIZE(total), BLOCK_SIZE>>>(
        (const float*)dense->data, d_values, d_row_indices, d_col_indices,
        d_nnz_counter, threshold, rows, cols);
    cudaDeviceSynchronize();

    cudaFree(d_nnz_counter);

    // Sort COO by row (using thrust)
    thrust::device_ptr<int> row_ptr(d_row_indices);
    thrust::device_ptr<int> col_ptr(d_col_indices);
    thrust::device_ptr<float> val_ptr(d_values);

    // Create index array for sorting
    int* d_indices;
    cudaMalloc(&d_indices, nnz * sizeof(int));
    thrust::device_ptr<int> idx_ptr(d_indices);
    thrust::sequence(thrust::device, idx_ptr, idx_ptr + nnz);

    // Sort by row, then by column
    thrust::sort_by_key(thrust::device, row_ptr, row_ptr + nnz,
        thrust::make_zip_iterator(thrust::make_tuple(col_ptr, val_ptr)));

    cudaFree(d_indices);

    if (format == SPARSE_FORMAT_COO) {
        sparse->data.coo.values = d_values;
        sparse->data.coo.row_indices = d_row_indices;
        sparse->data.coo.col_indices = d_col_indices;
        sparse->data.coo.rows = rows;
        sparse->data.coo.cols = cols;
        sparse->data.coo.nnz = nnz;

        // Create cuSPARSE COO descriptor
        cusparseCreateCoo(&sparse->cusparse_desc,
            rows, cols, nnz,
            d_row_indices, d_col_indices, d_values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }
    else if (format == SPARSE_FORMAT_CSR) {
        // Convert COO to CSR
        int* d_row_ptrs;
        NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_row_ptrs, (rows + 1) * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);

        // Use cuSPARSE for COO to CSR conversion
        size_t bufferSize = 0;
        void* dBuffer = NULL;

        cusparseXcoo2csr(ctx->cusparse_handle,
            d_row_indices, nnz, rows,
            d_row_ptrs, CUSPARSE_INDEX_BASE_ZERO);

        cudaFree(d_row_indices);

        sparse->data.csr.values = d_values;
        sparse->data.csr.col_indices = d_col_indices;
        sparse->data.csr.row_ptrs = d_row_ptrs;
        sparse->data.csr.rows = rows;
        sparse->data.csr.cols = cols;
        sparse->data.csr.nnz = nnz;
        sparse->data.csr.sparsity = 1.0f - (float)nnz / (rows * cols);

        // Create cuSPARSE CSR descriptor
        cusparseCreateCsr(&sparse->cusparse_desc,
            rows, cols, nnz,
            d_row_ptrs, d_col_indices, d_values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_32I,
            CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }
    else {
        // Other formats: convert through CSR
        LOG_WARN("Format %d not directly supported, using CSR", format);
        sparse->format = SPARSE_FORMAT_CSR;

        int* d_row_ptrs;
        NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_row_ptrs, (rows + 1) * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);

        cusparseXcoo2csr(ctx->cusparse_handle,
            d_row_indices, nnz, rows,
            d_row_ptrs, CUSPARSE_INDEX_BASE_ZERO);

        cudaFree(d_row_indices);

        sparse->data.csr.values = d_values;
        sparse->data.csr.col_indices = d_col_indices;
        sparse->data.csr.row_ptrs = d_row_ptrs;
        sparse->data.csr.rows = rows;
        sparse->data.csr.cols = cols;
        sparse->data.csr.nnz = nnz;
        sparse->data.csr.sparsity = 1.0f - (float)nnz / (rows * cols);

        cusparseCreateCsr(&sparse->cusparse_desc,
            rows, cols, nnz,
            d_row_ptrs, d_col_indices, d_values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_32I,
            CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }

    return sparse;
}

nimcp_sparse_tensor_t* nimcp_sparse_from_coo(
    nimcp_sparse_ctx_t* ctx,
    const float* values,
    const int* row_idx,
    const int* col_idx,
    int rows,
    int cols,
    int nnz,
    nimcp_sparse_format_t target_format)
{
    if (!nimcp_gpu_recovery_is_initialized()) {
        nimcp_gpu_recovery_init(NULL);
    }

    if (!ctx || !values || !row_idx || !col_idx) {
        LOG_ERROR("Invalid parameters for sparse_from_coo");
        return NULL;
    }

    nimcp_sparse_tensor_t* sparse = (nimcp_sparse_tensor_t*)nimcp_calloc(1, sizeof(nimcp_sparse_tensor_t));
    if (!sparse) return NULL;

    sparse->format = target_format;
    sparse->on_device = true;
    sparse->ctx = ctx->gpu_ctx;
    sparse->owns_data = true;

    // Allocate and copy COO data to device
    float* d_values;
    int* d_row_indices;
    int* d_col_indices;

    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_values, nnz * sizeof(float)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_row_indices, nnz * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_col_indices, nnz * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);

    cudaMemcpy(d_values, values, nnz * sizeof(float), cudaMemcpyHostToDevice);
    cudaMemcpy(d_row_indices, row_idx, nnz * sizeof(int), cudaMemcpyHostToDevice);
    cudaMemcpy(d_col_indices, col_idx, nnz * sizeof(int), cudaMemcpyHostToDevice);

    if (target_format == SPARSE_FORMAT_COO) {
        sparse->data.coo.values = d_values;
        sparse->data.coo.row_indices = d_row_indices;
        sparse->data.coo.col_indices = d_col_indices;
        sparse->data.coo.rows = rows;
        sparse->data.coo.cols = cols;
        sparse->data.coo.nnz = nnz;

        cusparseCreateCoo(&sparse->cusparse_desc,
            rows, cols, nnz,
            d_row_indices, d_col_indices, d_values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }
    else if (target_format == SPARSE_FORMAT_CSR) {
        // Convert to CSR
        int* d_row_ptrs;
        NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&d_row_ptrs, (rows + 1) * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);

        // Sort COO by row first
        thrust::device_ptr<int> row_ptr(d_row_indices);
        thrust::device_ptr<int> col_ptr(d_col_indices);
        thrust::device_ptr<float> val_ptr(d_values);
        thrust::sort_by_key(thrust::device, row_ptr, row_ptr + nnz,
            thrust::make_zip_iterator(thrust::make_tuple(col_ptr, val_ptr)));

        cusparseXcoo2csr(ctx->cusparse_handle,
            d_row_indices, nnz, rows,
            d_row_ptrs, CUSPARSE_INDEX_BASE_ZERO);

        cudaFree(d_row_indices);

        sparse->data.csr.values = d_values;
        sparse->data.csr.col_indices = d_col_indices;
        sparse->data.csr.row_ptrs = d_row_ptrs;
        sparse->data.csr.rows = rows;
        sparse->data.csr.cols = cols;
        sparse->data.csr.nnz = nnz;
        sparse->data.csr.sparsity = 1.0f - (float)nnz / (rows * cols);

        cusparseCreateCsr(&sparse->cusparse_desc,
            rows, cols, nnz,
            d_row_ptrs, d_col_indices, d_values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_32I,
            CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }
    else {
        LOG_ERROR("Format %d not yet supported in from_coo", target_format);
        cudaFree(d_values);
        cudaFree(d_row_indices);
        cudaFree(d_col_indices);
        nimcp_free(sparse);
        return NULL;
    }

    return sparse;
}

nimcp_sparse_tensor_t* nimcp_sparse_from_csr(
    nimcp_sparse_ctx_t* ctx,
    const float* values,
    const int* col_indices,
    const int* row_ptrs,
    int rows,
    int cols,
    int nnz)
{
    if (!nimcp_gpu_recovery_is_initialized()) {
        nimcp_gpu_recovery_init(NULL);
    }

    if (!ctx || !values || !col_indices || !row_ptrs) {
        LOG_ERROR("Invalid parameters for sparse_from_csr");
        return NULL;
    }

    nimcp_sparse_tensor_t* sparse = (nimcp_sparse_tensor_t*)nimcp_calloc(1, sizeof(nimcp_sparse_tensor_t));
    if (!sparse) return NULL;

    sparse->format = SPARSE_FORMAT_CSR;
    sparse->on_device = true;
    sparse->ctx = ctx->gpu_ctx;
    sparse->owns_data = true;

    // Allocate and copy CSR data to device
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&sparse->data.csr.values, nnz * sizeof(float)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&sparse->data.csr.col_indices, nnz * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);
    NIMCP_CUDA_RECOVER_NULL(cudaMalloc(&sparse->data.csr.row_ptrs, (rows + 1) * sizeof(int)), GPU_ERROR_OUT_OF_MEMORY);

    cudaMemcpy(sparse->data.csr.values, values, nnz * sizeof(float), cudaMemcpyHostToDevice);
    cudaMemcpy(sparse->data.csr.col_indices, col_indices, nnz * sizeof(int), cudaMemcpyHostToDevice);
    cudaMemcpy(sparse->data.csr.row_ptrs, row_ptrs, (rows + 1) * sizeof(int), cudaMemcpyHostToDevice);

    sparse->data.csr.rows = rows;
    sparse->data.csr.cols = cols;
    sparse->data.csr.nnz = nnz;
    sparse->data.csr.sparsity = 1.0f - (float)nnz / (rows * cols);

    // Create cuSPARSE descriptor
    cusparseCreateCsr(&sparse->cusparse_desc,
        rows, cols, nnz,
        sparse->data.csr.row_ptrs,
        sparse->data.csr.col_indices,
        sparse->data.csr.values,
        CUSPARSE_INDEX_32I, CUSPARSE_INDEX_32I,
        CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);

    return sparse;
}

nimcp_gpu_tensor_t* nimcp_sparse_to_dense(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* sparse)
{
    if (!nimcp_gpu_recovery_is_initialized()) {
        nimcp_gpu_recovery_init(NULL);
    }

    if (!ctx || !sparse) {
        LOG_ERROR("Invalid parameters for sparse_to_dense");
        return NULL;
    }

    int rows, cols, nnz;
    get_sparse_dims(sparse, &rows, &cols, &nnz);

    // Create dense tensor
    size_t dims[2] = {(size_t)rows, (size_t)cols};
    nimcp_gpu_tensor_t* dense = nimcp_gpu_tensor_create(ctx->gpu_ctx, dims, 2, NIMCP_GPU_PRECISION_FP32);
    if (!dense) return NULL;

    // Zero initialize
    cudaMemset(dense->data, 0, rows * cols * sizeof(float));

    if (sparse->format == SPARSE_FORMAT_CSR) {
        kernel_csr_to_dense<<<rows, BLOCK_SIZE>>>(
            sparse->data.csr.values,
            sparse->data.csr.col_indices,
            sparse->data.csr.row_ptrs,
            (float*)dense->data,
            rows, cols);
    }
    else if (sparse->format == SPARSE_FORMAT_COO) {
        // Simple COO to dense
        float* h_values = (float*)nimcp_malloc(nnz * sizeof(float));
        int* h_row_idx = (int*)nimcp_malloc(nnz * sizeof(int));
        int* h_col_idx = (int*)nimcp_malloc(nnz * sizeof(int));
        float* h_dense = (float*)nimcp_calloc(rows * cols, sizeof(float));

        cudaMemcpy(h_values, sparse->data.coo.values, nnz * sizeof(float), cudaMemcpyDeviceToHost);
        cudaMemcpy(h_row_idx, sparse->data.coo.row_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost);
        cudaMemcpy(h_col_idx, sparse->data.coo.col_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost);

        for (int i = 0; i < nnz; i++) {
            h_dense[h_row_idx[i] * cols + h_col_idx[i]] = h_values[i];
        }

        cudaMemcpy(dense->data, h_dense, rows * cols * sizeof(float), cudaMemcpyHostToDevice);

        nimcp_free(h_values);
        nimcp_free(h_row_idx);
        nimcp_free(h_col_idx);
        nimcp_free(h_dense);
    }
    else {
        LOG_ERROR("Format %d not supported for to_dense", sparse->format);
        nimcp_gpu_tensor_destroy(dense);
        return NULL;
    }

    return dense;
}

nimcp_sparse_tensor_t* nimcp_sparse_tensor_clone(
    nimcp_sparse_ctx_t* ctx,
    const nimcp_sparse_tensor_t* tensor)
{
    if (!nimcp_gpu_recovery_is_initialized()) {
        nimcp_gpu_recovery_init(NULL);
    }

    if (!ctx || !tensor) return NULL;

    nimcp_sparse_tensor_t* clone = (nimcp_sparse_tensor_t*)nimcp_calloc(1, sizeof(nimcp_sparse_tensor_t));
    if (!clone) return NULL;

    clone->format = tensor->format;
    clone->on_device = true;
    clone->ctx = ctx->gpu_ctx;
    clone->owns_data = true;

    if (tensor->format == SPARSE_FORMAT_CSR) {
        int nnz = tensor->data.csr.nnz;
        int rows = tensor->data.csr.rows;
        int cols = tensor->data.csr.cols;

        cudaMalloc(&clone->data.csr.values, nnz * sizeof(float));
        cudaMalloc(&clone->data.csr.col_indices, nnz * sizeof(int));
        cudaMalloc(&clone->data.csr.row_ptrs, (rows + 1) * sizeof(int));

        cudaMemcpy(clone->data.csr.values, tensor->data.csr.values, nnz * sizeof(float), cudaMemcpyDeviceToDevice);
        cudaMemcpy(clone->data.csr.col_indices, tensor->data.csr.col_indices, nnz * sizeof(int), cudaMemcpyDeviceToDevice);
        cudaMemcpy(clone->data.csr.row_ptrs, tensor->data.csr.row_ptrs, (rows + 1) * sizeof(int), cudaMemcpyDeviceToDevice);

        clone->data.csr.rows = rows;
        clone->data.csr.cols = cols;
        clone->data.csr.nnz = nnz;
        clone->data.csr.sparsity = tensor->data.csr.sparsity;

        cusparseCreateCsr(&clone->cusparse_desc,
            rows, cols, nnz,
            clone->data.csr.row_ptrs,
            clone->data.csr.col_indices,
            clone->data.csr.values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_32I,
            CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }
    else if (tensor->format == SPARSE_FORMAT_COO) {
        int nnz = tensor->data.coo.nnz;
        int rows = tensor->data.coo.rows;
        int cols = tensor->data.coo.cols;

        cudaMalloc(&clone->data.coo.values, nnz * sizeof(float));
        cudaMalloc(&clone->data.coo.row_indices, nnz * sizeof(int));
        cudaMalloc(&clone->data.coo.col_indices, nnz * sizeof(int));

        cudaMemcpy(clone->data.coo.values, tensor->data.coo.values, nnz * sizeof(float), cudaMemcpyDeviceToDevice);
        cudaMemcpy(clone->data.coo.row_indices, tensor->data.coo.row_indices, nnz * sizeof(int), cudaMemcpyDeviceToDevice);
        cudaMemcpy(clone->data.coo.col_indices, tensor->data.coo.col_indices, nnz * sizeof(int), cudaMemcpyDeviceToDevice);

        clone->data.coo.rows = rows;
        clone->data.coo.cols = cols;
        clone->data.coo.nnz = nnz;

        cusparseCreateCoo(&clone->cusparse_desc,
            rows, cols, nnz,
            clone->data.coo.row_indices,
            clone->data.coo.col_indices,
            clone->data.coo.values,
            CUSPARSE_INDEX_32I, CUSPARSE_INDEX_BASE_ZERO, CUDA_R_32F);
    }
    else {
        LOG_ERROR("Clone not implemented for format %d", tensor->format);
        nimcp_free(clone);
        return NULL;
    }

    return clone;
}

void nimcp_sparse_tensor_destroy(nimcp_sparse_tensor_t* tensor)
{
    if (!tensor) return;

    if (tensor->cusparse_desc) {
        cusparseDestroySpMat(tensor->cusparse_desc);
    }

    if (tensor->owns_data && tensor->on_device) {
        switch (tensor->format) {
            case SPARSE_FORMAT_CSR:
                if (tensor->data.csr.values) cudaFree(tensor->data.csr.values);
                if (tensor->data.csr.col_indices) cudaFree(tensor->data.csr.col_indices);
                if (tensor->data.csr.row_ptrs) cudaFree(tensor->data.csr.row_ptrs);
                break;
            case SPARSE_FORMAT_CSC:
                if (tensor->data.csc.values) cudaFree(tensor->data.csc.values);
                if (tensor->data.csc.row_indices) cudaFree(tensor->data.csc.row_indices);
                if (tensor->data.csc.col_ptrs) cudaFree(tensor->data.csc.col_ptrs);
                break;
            case SPARSE_FORMAT_COO:
                if (tensor->data.coo.values) cudaFree(tensor->data.coo.values);
                if (tensor->data.coo.row_indices) cudaFree(tensor->data.coo.row_indices);
                if (tensor->data.coo.col_indices) cudaFree(tensor->data.coo.col_indices);
                break;
            case SPARSE_FORMAT_BSR:
                if (tensor->data.bsr.values) cudaFree(tensor->data.bsr.values);
                if (tensor->data.bsr.col_indices) cudaFree(tensor->data.bsr.col_indices);
                if (tensor->data.bsr.row_ptrs) cudaFree(tensor->data.bsr.row_ptrs);
                break;
            case SPARSE_FORMAT_ELL:
                if (tensor->data.ell.values) cudaFree(tensor->data.ell.values);
                if (tensor->data.ell.col_indices) cudaFree(tensor->data.ell.col_indices);
                break;
        }
    }

    nimcp_free(tensor);
}

nimcp_sparse_tensor_t* nimcp_sparse_convert(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* src,
    nimcp_sparse_format_t target_format)
{
    if (!ctx || !src) return NULL;

    if (src->format == target_format) {
        return nimcp_sparse_tensor_clone(ctx, src);
    }

    // Convert through dense for simplicity
    // (A more efficient implementation would use direct conversions)
    nimcp_gpu_tensor_t* dense = nimcp_sparse_to_dense(ctx, src);
    if (!dense) return NULL;

    nimcp_sparse_tensor_t* result = nimcp_sparse_from_dense(ctx, dense, target_format, 0.0f);
    nimcp_gpu_tensor_destroy(dense);

    return result;
}

//=============================================================================
// Sparse Matrix Operations (cuSPARSE wrappers)
//=============================================================================

nimcp_gpu_tensor_t* nimcp_sparse_mm(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* B,
    float alpha,
    float beta,
    nimcp_gpu_tensor_t* C)
{
    if (!ctx || !A || !B) {
        LOG_ERROR("Invalid parameters for sparse_mm");
        return NULL;
    }

    int A_rows, A_cols, A_nnz;
    get_sparse_dims(A, &A_rows, &A_cols, &A_nnz);

    if (B->ndim != 2) {
        LOG_ERROR("sparse_mm requires 2D dense tensor B");
        return NULL;
    }

    int B_rows = B->dims[0];
    int B_cols = B->dims[1];

    if (A_cols != B_rows) {
        LOG_ERROR("sparse_mm dimension mismatch: A[%d,%d] x B[%d,%d]", A_rows, A_cols, B_rows, B_cols);
        return NULL;
    }

    // Create output tensor if needed
    bool created_C = false;
    if (!C) {
        size_t C_dims[2] = {(size_t)A_rows, (size_t)B_cols};
        C = nimcp_gpu_tensor_create(ctx->gpu_ctx, C_dims, 2, NIMCP_GPU_PRECISION_FP32);
        if (!C) return NULL;
        created_C = true;
        beta = 0.0f;  // C is zero-initialized
    }

    // Create dense matrix descriptors
    cusparseDnMatDescr_t B_desc, C_desc;
    cusparseCreateDnMat(&B_desc, B_rows, B_cols, B_cols,
        B->data, CUDA_R_32F, CUSPARSE_ORDER_ROW);
    cusparseCreateDnMat(&C_desc, A_rows, B_cols, B_cols,
        C->data, CUDA_R_32F, CUSPARSE_ORDER_ROW);

    // Query workspace size
    size_t bufferSize = 0;
    cusparseSpMM_bufferSize(ctx->cusparse_handle,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        &alpha, A->cusparse_desc, B_desc, &beta, C_desc,
        CUDA_R_32F, CUSPARSE_SPMM_ALG_DEFAULT, &bufferSize);

    if (!nimcp_sparse_ctx_ensure_workspace(ctx, bufferSize)) {
        LOG_ERROR("Failed to allocate SpMM workspace");
        cusparseDestroyDnMat(B_desc);
        cusparseDestroyDnMat(C_desc);
        if (created_C) nimcp_gpu_tensor_destroy(C);
        return NULL;
    }

    // Execute SpMM
    cusparseStatus_t status = cusparseSpMM(ctx->cusparse_handle,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        &alpha, A->cusparse_desc, B_desc, &beta, C_desc,
        CUDA_R_32F, CUSPARSE_SPMM_ALG_DEFAULT, ctx->workspace);

    cusparseDestroyDnMat(B_desc);
    cusparseDestroyDnMat(C_desc);

    if (status != CUSPARSE_STATUS_SUCCESS) {
        LOG_ERROR("cusparseSpMM failed: %d", status);
        if (created_C) nimcp_gpu_tensor_destroy(C);
        return NULL;
    }

    return C;
}

nimcp_gpu_tensor_t* nimcp_sparse_mv(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* x,
    float alpha,
    float beta,
    nimcp_gpu_tensor_t* y)
{
    if (!ctx || !A || !x) {
        LOG_ERROR("Invalid parameters for sparse_mv");
        return NULL;
    }

    int A_rows, A_cols, A_nnz;
    get_sparse_dims(A, &A_rows, &A_cols, &A_nnz);

    if (x->numel != (size_t)A_cols) {
        LOG_ERROR("sparse_mv dimension mismatch: A[%d,%d] x x[%zu]", A_rows, A_cols, x->numel);
        return NULL;
    }

    // Create output vector if needed
    bool created_y = false;
    if (!y) {
        size_t y_dims[1] = {(size_t)A_rows};
        y = nimcp_gpu_tensor_create(ctx->gpu_ctx, y_dims, 1, NIMCP_GPU_PRECISION_FP32);
        if (!y) return NULL;
        created_y = true;
        beta = 0.0f;
    }

    // Create dense vector descriptors
    cusparseDnVecDescr_t x_desc, y_desc;
    cusparseCreateDnVec(&x_desc, A_cols, x->data, CUDA_R_32F);
    cusparseCreateDnVec(&y_desc, A_rows, y->data, CUDA_R_32F);

    // Query workspace
    size_t bufferSize = 0;
    cusparseSpMV_bufferSize(ctx->cusparse_handle,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        &alpha, A->cusparse_desc, x_desc, &beta, y_desc,
        CUDA_R_32F, CUSPARSE_SPMV_ALG_DEFAULT, &bufferSize);

    if (!nimcp_sparse_ctx_ensure_workspace(ctx, bufferSize)) {
        cusparseDestroyDnVec(x_desc);
        cusparseDestroyDnVec(y_desc);
        if (created_y) nimcp_gpu_tensor_destroy(y);
        return NULL;
    }

    // Execute SpMV
    cusparseStatus_t status = cusparseSpMV(ctx->cusparse_handle,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        &alpha, A->cusparse_desc, x_desc, &beta, y_desc,
        CUDA_R_32F, CUSPARSE_SPMV_ALG_DEFAULT, ctx->workspace);

    cusparseDestroyDnVec(x_desc);
    cusparseDestroyDnVec(y_desc);

    if (status != CUSPARSE_STATUS_SUCCESS) {
        LOG_ERROR("cusparseSpMV failed: %d", status);
        if (created_y) nimcp_gpu_tensor_destroy(y);
        return NULL;
    }

    return y;
}

nimcp_gpu_tensor_t* nimcp_sparse_mm_transpose(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* B,
    float alpha,
    float beta,
    nimcp_gpu_tensor_t* C)
{
    if (!ctx || !A || !B) return NULL;

    int A_rows, A_cols, A_nnz;
    get_sparse_dims(A, &A_rows, &A_cols, &A_nnz);

    int B_rows = B->dims[0];
    int B_cols = B->dims[1];

    // A^T is [A_cols, A_rows], so A^T x B requires B_rows == A_rows
    if (A_rows != B_rows) {
        LOG_ERROR("sparse_mm_transpose dimension mismatch");
        return NULL;
    }

    bool created_C = false;
    if (!C) {
        size_t C_dims[2] = {(size_t)A_cols, (size_t)B_cols};
        C = nimcp_gpu_tensor_create(ctx->gpu_ctx, C_dims, 2, NIMCP_GPU_PRECISION_FP32);
        if (!C) return NULL;
        created_C = true;
        beta = 0.0f;
    }

    cusparseDnMatDescr_t B_desc, C_desc;
    cusparseCreateDnMat(&B_desc, B_rows, B_cols, B_cols, B->data, CUDA_R_32F, CUSPARSE_ORDER_ROW);
    cusparseCreateDnMat(&C_desc, A_cols, B_cols, B_cols, C->data, CUDA_R_32F, CUSPARSE_ORDER_ROW);

    size_t bufferSize = 0;
    cusparseSpMM_bufferSize(ctx->cusparse_handle,
        CUSPARSE_OPERATION_TRANSPOSE,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        &alpha, A->cusparse_desc, B_desc, &beta, C_desc,
        CUDA_R_32F, CUSPARSE_SPMM_ALG_DEFAULT, &bufferSize);

    if (!nimcp_sparse_ctx_ensure_workspace(ctx, bufferSize)) {
        cusparseDestroyDnMat(B_desc);
        cusparseDestroyDnMat(C_desc);
        if (created_C) nimcp_gpu_tensor_destroy(C);
        return NULL;
    }

    cusparseStatus_t status = cusparseSpMM(ctx->cusparse_handle,
        CUSPARSE_OPERATION_TRANSPOSE,
        CUSPARSE_OPERATION_NON_TRANSPOSE,
        &alpha, A->cusparse_desc, B_desc, &beta, C_desc,
        CUDA_R_32F, CUSPARSE_SPMM_ALG_DEFAULT, ctx->workspace);

    cusparseDestroyDnMat(B_desc);
    cusparseDestroyDnMat(C_desc);

    if (status != CUSPARSE_STATUS_SUCCESS) {
        if (created_C) nimcp_gpu_tensor_destroy(C);
        return NULL;
    }

    return C;
}

nimcp_sparse_tensor_t* nimcp_sparse_scale(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* A,
    float scale)
{
    if (!ctx || !A) return NULL;

    int rows, cols, nnz;
    get_sparse_dims(A, &rows, &cols, &nnz);

    float* values = NULL;
    switch (A->format) {
        case SPARSE_FORMAT_CSR: values = A->data.csr.values; break;
        case SPARSE_FORMAT_CSC: values = A->data.csc.values; break;
        case SPARSE_FORMAT_COO: values = A->data.coo.values; break;
        default: return NULL;
    }

    kernel_sparse_scale<<<GRID_SIZE(nnz), BLOCK_SIZE>>>(values, scale, nnz);
    cudaDeviceSynchronize();

    return A;
}

nimcp_sparse_tensor_t* nimcp_sparse_add(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* A,
    nimcp_sparse_tensor_t* B,
    float alpha,
    float beta)
{
    if (!ctx || !A || !B) return NULL;

    // For simplicity, convert to dense, add, convert back
    // A more efficient implementation would use cuSPARSE sparse+sparse
    nimcp_gpu_tensor_t* dense_A = nimcp_sparse_to_dense(ctx, A);
    nimcp_gpu_tensor_t* dense_B = nimcp_sparse_to_dense(ctx, B);

    if (!dense_A || !dense_B) {
        nimcp_gpu_tensor_destroy(dense_A);
        nimcp_gpu_tensor_destroy(dense_B);
        return NULL;
    }

    // C = alpha*A + beta*B
    int n = dense_A->numel;
    float* d_A = (float*)dense_A->data;
    float* d_B = (float*)dense_B->data;

    // In-place: A = alpha*A + beta*B
    cublasHandle_t cublas = (cublasHandle_t)ctx->gpu_ctx->cublas_handle;
    cublasSscal(cublas, n, &alpha, d_A, 1);
    cublasSaxpy(cublas, n, &beta, d_B, 1, d_A, 1);

    nimcp_gpu_tensor_destroy(dense_B);

    // Convert result back to sparse (threshold 0 to preserve structure)
    nimcp_sparse_tensor_t* result = nimcp_sparse_from_dense(ctx, dense_A, A->format, 1e-8f);
    nimcp_gpu_tensor_destroy(dense_A);

    return result;
}

nimcp_gpu_tensor_t* nimcp_sparse_mm_batched(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* B,
    float alpha,
    float beta,
    nimcp_gpu_tensor_t* C)
{
    if (!ctx || !A || !B) return NULL;

    if (B->ndim != 3) {
        LOG_ERROR("sparse_mm_batched requires 3D dense tensor B [batch, K, N]");
        return NULL;
    }

    int batch = B->dims[0];
    int K = B->dims[1];
    int N = B->dims[2];

    int A_rows, A_cols, A_nnz;
    get_sparse_dims(A, &A_rows, &A_cols, &A_nnz);

    if (A_cols != K) {
        LOG_ERROR("Dimension mismatch in batched SpMM");
        return NULL;
    }

    // Create output if needed
    bool created_C = false;
    if (!C) {
        size_t C_dims[3] = {(size_t)batch, (size_t)A_rows, (size_t)N};
        C = nimcp_gpu_tensor_create(ctx->gpu_ctx, C_dims, 3, NIMCP_GPU_PRECISION_FP32);
        if (!C) return NULL;
        created_C = true;
        beta = 0.0f;
    }

    // Process each batch element
    size_t B_stride = K * N;
    size_t C_stride = A_rows * N;

    for (int b = 0; b < batch; b++) {
        // Create views for this batch
        size_t B_dims[2] = {(size_t)K, (size_t)N};
        size_t C_dims[2] = {(size_t)A_rows, (size_t)N};

        // Manual SpMM for this batch slice
        cusparseDnMatDescr_t B_desc, C_desc;
        cusparseCreateDnMat(&B_desc, K, N, N,
            (float*)B->data + b * B_stride, CUDA_R_32F, CUSPARSE_ORDER_ROW);
        cusparseCreateDnMat(&C_desc, A_rows, N, N,
            (float*)C->data + b * C_stride, CUDA_R_32F, CUSPARSE_ORDER_ROW);

        size_t bufferSize = 0;
        cusparseSpMM_bufferSize(ctx->cusparse_handle,
            CUSPARSE_OPERATION_NON_TRANSPOSE,
            CUSPARSE_OPERATION_NON_TRANSPOSE,
            &alpha, A->cusparse_desc, B_desc, &beta, C_desc,
            CUDA_R_32F, CUSPARSE_SPMM_ALG_DEFAULT, &bufferSize);

        nimcp_sparse_ctx_ensure_workspace(ctx, bufferSize);

        cusparseSpMM(ctx->cusparse_handle,
            CUSPARSE_OPERATION_NON_TRANSPOSE,
            CUSPARSE_OPERATION_NON_TRANSPOSE,
            &alpha, A->cusparse_desc, B_desc, &beta, C_desc,
            CUDA_R_32F, CUSPARSE_SPMM_ALG_DEFAULT, ctx->workspace);

        cusparseDestroyDnMat(B_desc);
        cusparseDestroyDnMat(C_desc);
    }

    return C;
}

//=============================================================================
// Custom Operations Implementation
//=============================================================================

bool nimcp_sparse_attention(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* Q,
    nimcp_gpu_tensor_t* K,
    nimcp_gpu_tensor_t* V,
    nimcp_sparse_tensor_t* attention_mask,
    nimcp_gpu_tensor_t* output)
{
    if (!ctx || !Q || !K || !V || !attention_mask || !output) {
        return false;
    }

    if (Q->ndim != 4) {
        LOG_ERROR("Sparse attention requires 4D tensors [batch, heads, seq, dim]");
        return false;
    }

    int batch = Q->dims[0];
    int heads = Q->dims[1];
    int seq_len = Q->dims[2];
    int head_dim = Q->dims[3];

    if (attention_mask->format != SPARSE_FORMAT_CSR) {
        LOG_ERROR("Sparse attention requires CSR mask");
        return false;
    }

    dim3 grid(seq_len, heads, batch);
    dim3 block(min(head_dim, 256));
    size_t shared_mem = head_dim * sizeof(float) * 2;

    kernel_sparse_attention<<<grid, block, shared_mem>>>(
        (const float*)Q->data,
        (const float*)K->data,
        (const float*)V->data,
        attention_mask->data.csr.row_ptrs,
        attention_mask->data.csr.col_indices,
        (float*)output->data,
        batch, heads, seq_len, head_dim);

    NIMCP_CUDA_RECOVER_LAST(GPU_ERROR_KERNEL_LAUNCH);
    return true;
}

bool nimcp_sparse_apply_mask(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* dense_in,
    nimcp_sparse_tensor_t* mask,
    nimcp_gpu_tensor_t* dense_out)
{
    if (!ctx || !dense_in || !mask || !dense_out) return false;

    if (mask->format != SPARSE_FORMAT_CSR) {
        LOG_ERROR("apply_mask requires CSR format mask");
        return false;
    }

    int rows = mask->data.csr.rows;
    int cols = mask->data.csr.cols;

    kernel_apply_sparse_mask_csr<<<rows, BLOCK_SIZE>>>(
        (const float*)dense_in->data,
        (float*)dense_out->data,
        mask->data.csr.row_ptrs,
        mask->data.csr.col_indices,
        rows, cols);

    NIMCP_CUDA_RECOVER_LAST(GPU_ERROR_KERNEL_LAUNCH);
    return true;
}

bool nimcp_sparse_grad_accumulate(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* sparse_grad,
    nimcp_gpu_tensor_t* dense_grad)
{
    if (!ctx || !sparse_grad || !dense_grad) return false;

    if (sparse_grad->format != SPARSE_FORMAT_CSR) {
        LOG_ERROR("grad_accumulate requires CSR format");
        return false;
    }

    int rows = sparse_grad->data.csr.rows;
    int cols = sparse_grad->data.csr.cols;

    kernel_sparse_grad_accumulate_csr<<<rows, BLOCK_SIZE>>>(
        sparse_grad->data.csr.values,
        sparse_grad->data.csr.row_ptrs,
        sparse_grad->data.csr.col_indices,
        (float*)dense_grad->data,
        rows, cols);

    NIMCP_CUDA_RECOVER_LAST(GPU_ERROR_KERNEL_LAUNCH);
    return true;
}

//=============================================================================
// Sparse Neural Network Layers
//=============================================================================

nimcp_gpu_tensor_t* nimcp_sparse_linear_forward(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* weight,
    nimcp_gpu_tensor_t* bias,
    nimcp_gpu_tensor_t* input)
{
    if (!ctx || !weight || !input) return NULL;

    // output = input @ weight^T + bias
    // weight: [out_features, in_features]
    // input: [batch, in_features]
    // output: [batch, out_features]

    nimcp_gpu_tensor_t* output = nimcp_sparse_mm_transpose(ctx, weight, input, 1.0f, 0.0f, NULL);
    if (!output) return NULL;

    // Add bias if present
    if (bias) {
        int out_features = output->dims[1];
        int batch = output->dims[0];

        // Broadcast bias across batch
        // output[i, :] += bias[:]
        cublasHandle_t cublas = (cublasHandle_t)ctx->gpu_ctx->cublas_handle;
        float one = 1.0f;
        for (int b = 0; b < batch; b++) {
            cublasSaxpy(cublas, out_features, &one,
                (const float*)bias->data, 1,
                (float*)output->data + b * out_features, 1);
        }
    }

    return output;
}

bool nimcp_sparse_linear_backward(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* weight,
    nimcp_gpu_tensor_t* input,
    nimcp_gpu_tensor_t* grad_output,
    nimcp_sparse_tensor_t* grad_weight,
    nimcp_gpu_tensor_t* grad_input)
{
    if (!ctx || !weight || !input || !grad_output) return false;

    // grad_input = grad_output @ weight (if grad_input is requested)
    if (grad_input) {
        nimcp_sparse_mm(ctx, weight, grad_output, 1.0f, 0.0f, grad_input);
    }

    // grad_weight = grad_output^T @ input (sparse gradient)
    // This is more complex - we need to compute only at sparse positions
    if (grad_weight) {
        // For simplicity, compute dense gradient and mask to sparse pattern
        nimcp_gpu_tensor_t* dense_grad = nimcp_sparse_to_dense(ctx, grad_weight);
        if (dense_grad) {
            // Compute: grad_weight_dense = grad_output^T @ input
            int batch = grad_output->dims[0];
            int out_features = grad_output->dims[1];
            int in_features = input->dims[1];

            cublasHandle_t cublas = (cublasHandle_t)ctx->gpu_ctx->cublas_handle;
            float alpha = 1.0f, beta = 0.0f;

            // grad_output is [batch, out], input is [batch, in]
            // result is [out, in] = grad_output^T @ input
            cublasSgemm(cublas,
                CUBLAS_OP_N, CUBLAS_OP_T,
                in_features, out_features, batch,
                &alpha,
                (const float*)input->data, in_features,
                (const float*)grad_output->data, out_features,
                &beta,
                (float*)dense_grad->data, in_features);

            // Apply sparse mask
            nimcp_sparse_apply_mask(ctx, dense_grad, grad_weight, dense_grad);

            // Copy masked values back to grad_weight
            // (This is a simplified approach; production code would be more efficient)
            nimcp_gpu_tensor_destroy(dense_grad);
        }
    }

    return true;
}

nimcp_gpu_tensor_t* nimcp_sparse_synapse_forward(
    nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* connectivity,
    nimcp_gpu_tensor_t* pre_activity)
{
    // Simply use SpMV: post = connectivity @ pre
    return nimcp_sparse_mv(ctx, connectivity, pre_activity, 1.0f, 0.0f, NULL);
}

//=============================================================================
// Pruning Utilities
//=============================================================================

nimcp_sparse_tensor_t* nimcp_magnitude_prune(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* dense,
    float sparsity_target)
{
    if (!ctx || !dense) return NULL;
    if (sparsity_target <= 0.0f || sparsity_target >= 1.0f) {
        LOG_ERROR("Sparsity target must be in (0, 1), got %f", sparsity_target);
        return NULL;
    }

    int n = dense->numel;
    int target_nnz = (int)(n * (1.0f - sparsity_target));

    // Find threshold using histogram approach
    // First, find max absolute value
    float* h_data = (float*)nimcp_malloc(n * sizeof(float));
    cudaMemcpy(h_data, dense->data, n * sizeof(float), cudaMemcpyDeviceToHost);

    float max_abs = 0.0f;
    for (int i = 0; i < n; i++) {
        max_abs = fmaxf(max_abs, fabsf(h_data[i]));
    }

    // Binary search for threshold
    float lo = 0.0f, hi = max_abs;
    float threshold = 0.0f;

    for (int iter = 0; iter < 32; iter++) {
        threshold = (lo + hi) / 2.0f;
        int count = 0;
        for (int i = 0; i < n; i++) {
            if (fabsf(h_data[i]) >= threshold) count++;
        }

        if (count > target_nnz) {
            lo = threshold;
        } else {
            hi = threshold;
        }
    }

    nimcp_free(h_data);

    return nimcp_sparse_from_dense(ctx, dense, SPARSE_FORMAT_CSR, threshold);
}

nimcp_sparse_tensor_t* nimcp_structured_prune(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* dense,
    int N,
    int M)
{
    if (!ctx || !dense) return NULL;
    if (N <= 0 || M <= 0 || N > M) {
        LOG_ERROR("Invalid N:M sparsity parameters: %d:%d", N, M);
        return NULL;
    }

    // Create output tensor
    size_t dims[2] = {dense->dims[0], dense->dims[1]};
    nimcp_gpu_tensor_t* pruned = nimcp_gpu_tensor_create(ctx->gpu_ctx, dims, 2, NIMCP_GPU_PRECISION_FP32);
    if (!pruned) return NULL;

    int total = dense->numel;
    int num_groups = (total + M - 1) / M;

    kernel_structured_prune<<<GRID_SIZE(num_groups), BLOCK_SIZE>>>(
        (const float*)dense->data,
        (float*)pruned->data,
        NULL,  // No mask output
        N, M, total);

    cudaDeviceSynchronize();

    // Convert to sparse
    nimcp_sparse_tensor_t* sparse = nimcp_sparse_from_dense(ctx, pruned, SPARSE_FORMAT_CSR, 1e-8f);
    nimcp_gpu_tensor_destroy(pruned);

    return sparse;
}

nimcp_sparse_tensor_t* nimcp_threshold_prune(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* dense,
    float threshold)
{
    return nimcp_sparse_from_dense(ctx, dense, SPARSE_FORMAT_CSR, threshold);
}

nimcp_sparse_tensor_t* nimcp_sparse_random(
    nimcp_sparse_ctx_t* ctx,
    int rows,
    int cols,
    float density,
    nimcp_sparse_format_t format)
{
    if (!ctx) return NULL;
    if (density <= 0.0f || density > 1.0f) {
        LOG_ERROR("Density must be in (0, 1], got %f", density);
        return NULL;
    }

    int total = rows * cols;
    int nnz = (int)(total * density);
    if (nnz < 1) nnz = 1;

    // Allocate COO arrays
    float* d_values;
    int* d_row_indices;
    int* d_col_indices;

    cudaMalloc(&d_values, nnz * sizeof(float));
    cudaMalloc(&d_row_indices, nnz * sizeof(int));
    cudaMalloc(&d_col_indices, nnz * sizeof(int));

    // Generate random sparse pattern
    unsigned long long seed = (unsigned long long)time(NULL);
    kernel_random_sparse_coo<<<GRID_SIZE(nnz), BLOCK_SIZE>>>(
        d_values, d_row_indices, d_col_indices,
        rows, cols, nnz, seed);

    cudaDeviceSynchronize();

    // Copy to host and create sparse tensor
    float* h_values = (float*)nimcp_malloc(nnz * sizeof(float));
    int* h_rows = (int*)nimcp_malloc(nnz * sizeof(int));
    int* h_cols = (int*)nimcp_malloc(nnz * sizeof(int));

    cudaMemcpy(h_values, d_values, nnz * sizeof(float), cudaMemcpyDeviceToHost);
    cudaMemcpy(h_rows, d_row_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost);
    cudaMemcpy(h_cols, d_col_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost);

    cudaFree(d_values);
    cudaFree(d_row_indices);
    cudaFree(d_col_indices);

    nimcp_sparse_tensor_t* sparse = nimcp_sparse_from_coo(ctx, h_values, h_rows, h_cols, rows, cols, nnz, format);

    nimcp_free(h_values);
    nimcp_free(h_rows);
    nimcp_free(h_cols);

    return sparse;
}

//=============================================================================
// Statistics and Utilities
//=============================================================================

nimcp_sparsity_stats_t nimcp_sparse_get_stats(nimcp_sparse_tensor_t* tensor)
{
    nimcp_sparsity_stats_t stats = {0};

    if (!tensor) return stats;

    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);

    stats.nnz = nnz;
    stats.total_elements = rows * cols;
    stats.density_ratio = (float)nnz / stats.total_elements;
    stats.sparsity_ratio = 1.0f - stats.density_ratio;
    stats.avg_nnz_per_row = (float)nnz / rows;

    // Compute row statistics for CSR
    if (tensor->format == SPARSE_FORMAT_CSR) {
        int* h_row_ptrs = (int*)nimcp_malloc((rows + 1) * sizeof(int));
        cudaMemcpy(h_row_ptrs, tensor->data.csr.row_ptrs, (rows + 1) * sizeof(int), cudaMemcpyDeviceToHost);

        stats.min_nnz_per_row = INT_MAX;
        stats.max_nnz_per_row = 0;
        float sum_sq = 0.0f;

        for (int i = 0; i < rows; i++) {
            int row_nnz = h_row_ptrs[i + 1] - h_row_ptrs[i];
            stats.min_nnz_per_row = fminf(stats.min_nnz_per_row, (float)row_nnz);
            stats.max_nnz_per_row = fmaxf(stats.max_nnz_per_row, (float)row_nnz);
            float diff = row_nnz - stats.avg_nnz_per_row;
            sum_sq += diff * diff;
        }

        stats.std_nnz_per_row = sqrtf(sum_sq / rows);
        nimcp_free(h_row_ptrs);
    }

    // Memory calculations
    stats.dense_memory_bytes = stats.total_elements * sizeof(float);

    switch (tensor->format) {
        case SPARSE_FORMAT_CSR:
            stats.sparse_memory_bytes = nnz * sizeof(float) + nnz * sizeof(int) + (rows + 1) * sizeof(int);
            break;
        case SPARSE_FORMAT_COO:
            stats.sparse_memory_bytes = nnz * sizeof(float) + 2 * nnz * sizeof(int);
            break;
        default:
            stats.sparse_memory_bytes = nnz * sizeof(float);
    }

    stats.memory_savings_percent = 100.0f * (1.0f - (float)stats.sparse_memory_bytes / stats.dense_memory_bytes);

    return stats;
}

float nimcp_sparse_compute_density(
    nimcp_sparse_ctx_t* ctx,
    nimcp_gpu_tensor_t* dense,
    float threshold)
{
    if (!ctx || !dense) return 0.0f;

    int n = dense->numel;

    int* d_count;
    cudaMalloc(&d_count, sizeof(int));
    cudaMemset(d_count, 0, sizeof(int));

    kernel_count_nonzeros<<<GRID_SIZE(n), BLOCK_SIZE>>>(
        (const float*)dense->data, d_count, threshold, n);

    int nnz;
    cudaMemcpy(&nnz, d_count, sizeof(int), cudaMemcpyDeviceToHost);
    cudaFree(d_count);

    return (float)nnz / n;
}

void nimcp_sparse_print_info(nimcp_sparse_tensor_t* tensor, bool verbose)
{
    if (!tensor) {
        printf("Sparse tensor: NULL\n");
        return;
    }

    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);

    printf("Sparse tensor: %dx%d, %d nnz (%.1f%% dense)\n",
           rows, cols, nnz, 100.0f * nnz / (rows * cols));
    printf("  Format: %s\n", nimcp_sparse_format_name(tensor->format));
    printf("  On device: %s\n", tensor->on_device ? "yes" : "no");

    if (verbose) {
        nimcp_sparsity_stats_t stats = nimcp_sparse_get_stats(tensor);
        printf("  Avg nnz/row: %.2f\n", stats.avg_nnz_per_row);
        printf("  Min nnz/row: %.0f\n", stats.min_nnz_per_row);
        printf("  Max nnz/row: %.0f\n", stats.max_nnz_per_row);
        printf("  Dense memory: %.2f MB\n", stats.dense_memory_bytes / (1024.0f * 1024.0f));
        printf("  Sparse memory: %.2f MB\n", stats.sparse_memory_bytes / (1024.0f * 1024.0f));
        printf("  Memory savings: %.1f%%\n", stats.memory_savings_percent);
    }
}

bool nimcp_sparse_validate(nimcp_sparse_tensor_t* tensor)
{
    if (!tensor) return false;

    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);

    if (rows <= 0 || cols <= 0 || nnz < 0) {
        LOG_ERROR("Invalid sparse tensor dimensions: %dx%d, %d nnz", rows, cols, nnz);
        return false;
    }

    if (tensor->format == SPARSE_FORMAT_CSR) {
        if (!tensor->data.csr.values || !tensor->data.csr.col_indices || !tensor->data.csr.row_ptrs) {
            LOG_ERROR("CSR tensor has NULL pointers");
            return false;
        }

        // Check row_ptrs[0] = 0 and row_ptrs[rows] = nnz
        int first, last;
        cudaMemcpy(&first, tensor->data.csr.row_ptrs, sizeof(int), cudaMemcpyDeviceToHost);
        cudaMemcpy(&last, tensor->data.csr.row_ptrs + rows, sizeof(int), cudaMemcpyDeviceToHost);

        if (first != 0) {
            LOG_ERROR("CSR row_ptrs[0] = %d, expected 0", first);
            return false;
        }
        if (last != nnz) {
            LOG_ERROR("CSR row_ptrs[rows] = %d, expected %d", last, nnz);
            return false;
        }
    }

    return true;
}

//=============================================================================
// Host-Device Transfer
//=============================================================================

bool nimcp_sparse_to_host_csr(
    nimcp_sparse_tensor_t* tensor,
    float* values,
    int* col_indices,
    int* row_ptrs)
{
    if (!tensor || tensor->format != SPARSE_FORMAT_CSR) return false;
    if (!values || !col_indices || !row_ptrs) return false;

    int nnz = tensor->data.csr.nnz;
    int rows = tensor->data.csr.rows;

    NIMCP_CUDA_RECOVER(cudaMemcpy(values, tensor->data.csr.values, nnz * sizeof(float), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);
    NIMCP_CUDA_RECOVER(cudaMemcpy(col_indices, tensor->data.csr.col_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);
    NIMCP_CUDA_RECOVER(cudaMemcpy(row_ptrs, tensor->data.csr.row_ptrs, (rows + 1) * sizeof(int), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);

    return true;
}

bool nimcp_sparse_to_host_coo(
    nimcp_sparse_tensor_t* tensor,
    float* values,
    int* row_indices,
    int* col_indices)
{
    if (!tensor || tensor->format != SPARSE_FORMAT_COO) return false;
    if (!values || !row_indices || !col_indices) return false;

    int nnz = tensor->data.coo.nnz;

    NIMCP_CUDA_RECOVER(cudaMemcpy(values, tensor->data.coo.values, nnz * sizeof(float), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);
    NIMCP_CUDA_RECOVER(cudaMemcpy(row_indices, tensor->data.coo.row_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);
    NIMCP_CUDA_RECOVER(cudaMemcpy(col_indices, tensor->data.coo.col_indices, nnz * sizeof(int), cudaMemcpyDeviceToHost), GPU_ERROR_CUDA_RUNTIME);

    return true;
}

//=============================================================================
// Format Utilities
//=============================================================================

int nimcp_sparse_rows(const nimcp_sparse_tensor_t* tensor)
{
    if (!tensor) return 0;
    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);
    return rows;
}

int nimcp_sparse_cols(const nimcp_sparse_tensor_t* tensor)
{
    if (!tensor) return 0;
    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);
    return cols;
}

int nimcp_sparse_nnz(const nimcp_sparse_tensor_t* tensor)
{
    if (!tensor) return 0;
    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);
    return nnz;
}

float nimcp_sparse_sparsity(const nimcp_sparse_tensor_t* tensor)
{
    if (!tensor) return 0.0f;
    int rows, cols, nnz;
    get_sparse_dims(tensor, &rows, &cols, &nnz);
    return 1.0f - (float)nnz / (rows * cols);
}

const char* nimcp_sparse_format_name(nimcp_sparse_format_t format)
{
    switch (format) {
        case SPARSE_FORMAT_CSR: return "CSR";
        case SPARSE_FORMAT_CSC: return "CSC";
        case SPARSE_FORMAT_COO: return "COO";
        case SPARSE_FORMAT_BSR: return "BSR";
        case SPARSE_FORMAT_ELL: return "ELL";
        default: return "UNKNOWN";
    }
}

#else // !NIMCP_ENABLE_CUDA

//=============================================================================
// CPU Fallback Stubs
//=============================================================================

#include "gpu/sparse/nimcp_sparse_gpu.h"
#include "utils/logging/nimcp_logging.h"
#include <stdlib.h>
#include <string.h>

#define LOG_MODULE "SPARSE_GPU"

nimcp_sparse_ctx_t* nimcp_sparse_ctx_create(nimcp_gpu_context_t* gpu_ctx)
{
    LOG_WARN("CUDA not available - sparse GPU operations disabled");
    return NULL;
}

void nimcp_sparse_ctx_destroy(nimcp_sparse_ctx_t* ctx) {}

bool nimcp_sparse_ctx_ensure_workspace(nimcp_sparse_ctx_t* ctx, size_t size) { return false; }

nimcp_sparse_tensor_t* nimcp_sparse_from_dense(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* dense,
    nimcp_sparse_format_t format, float threshold) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_from_coo(nimcp_sparse_ctx_t* ctx, const float* values,
    const int* row_idx, const int* col_idx, int rows, int cols, int nnz,
    nimcp_sparse_format_t target_format) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_from_csr(nimcp_sparse_ctx_t* ctx, const float* values,
    const int* col_indices, const int* row_ptrs, int rows, int cols, int nnz) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_convert(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* src,
    nimcp_sparse_format_t target_format) { return NULL; }

nimcp_gpu_tensor_t* nimcp_sparse_to_dense(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* sparse) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_tensor_clone(nimcp_sparse_ctx_t* ctx, const nimcp_sparse_tensor_t* tensor) { return NULL; }

void nimcp_sparse_tensor_destroy(nimcp_sparse_tensor_t* tensor)
{
    if (tensor) nimcp_free(tensor);
}

nimcp_gpu_tensor_t* nimcp_sparse_mm(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* B, float alpha, float beta, nimcp_gpu_tensor_t* C) { return NULL; }

nimcp_gpu_tensor_t* nimcp_sparse_mv(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* x, float alpha, float beta, nimcp_gpu_tensor_t* y) { return NULL; }

nimcp_gpu_tensor_t* nimcp_sparse_mm_transpose(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* B, float alpha, float beta, nimcp_gpu_tensor_t* C) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_add(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* A,
    nimcp_sparse_tensor_t* B, float alpha, float beta) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_scale(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* A, float scale) { return NULL; }

nimcp_gpu_tensor_t* nimcp_sparse_mm_batched(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* A,
    nimcp_gpu_tensor_t* B, float alpha, float beta, nimcp_gpu_tensor_t* C) { return NULL; }

bool nimcp_sparse_attention(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* Q, nimcp_gpu_tensor_t* K,
    nimcp_gpu_tensor_t* V, nimcp_sparse_tensor_t* mask, nimcp_gpu_tensor_t* output) { return false; }

bool nimcp_sparse_apply_mask(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* in,
    nimcp_sparse_tensor_t* mask, nimcp_gpu_tensor_t* out) { return false; }

bool nimcp_sparse_grad_accumulate(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* sparse,
    nimcp_gpu_tensor_t* dense) { return false; }

nimcp_gpu_tensor_t* nimcp_sparse_linear_forward(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* weight,
    nimcp_gpu_tensor_t* bias, nimcp_gpu_tensor_t* input) { return NULL; }

bool nimcp_sparse_linear_backward(nimcp_sparse_ctx_t* ctx, nimcp_sparse_tensor_t* weight,
    nimcp_gpu_tensor_t* input, nimcp_gpu_tensor_t* grad_output,
    nimcp_sparse_tensor_t* grad_weight, nimcp_gpu_tensor_t* grad_input) { return false; }

nimcp_gpu_tensor_t* nimcp_sparse_synapse_forward(nimcp_sparse_ctx_t* ctx,
    nimcp_sparse_tensor_t* connectivity, nimcp_gpu_tensor_t* pre_activity) { return NULL; }

nimcp_sparse_tensor_t* nimcp_magnitude_prune(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* dense,
    float sparsity_target) { return NULL; }

nimcp_sparse_tensor_t* nimcp_structured_prune(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* dense,
    int N, int M) { return NULL; }

nimcp_sparse_tensor_t* nimcp_threshold_prune(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* dense,
    float threshold) { return NULL; }

nimcp_sparse_tensor_t* nimcp_sparse_random(nimcp_sparse_ctx_t* ctx, int rows, int cols,
    float density, nimcp_sparse_format_t format) { return NULL; }

nimcp_sparsity_stats_t nimcp_sparse_get_stats(nimcp_sparse_tensor_t* tensor)
{
    nimcp_sparsity_stats_t stats = {0};
    return stats;
}

float nimcp_sparse_compute_density(nimcp_sparse_ctx_t* ctx, nimcp_gpu_tensor_t* dense, float threshold) { return 0.0f; }

void nimcp_sparse_print_info(nimcp_sparse_tensor_t* tensor, bool verbose)
{
    printf("Sparse tensor: CUDA not available\n");
}

bool nimcp_sparse_validate(nimcp_sparse_tensor_t* tensor) { return false; }

bool nimcp_sparse_to_host_csr(nimcp_sparse_tensor_t* tensor, float* values,
    int* col_indices, int* row_ptrs) { return false; }

bool nimcp_sparse_to_host_coo(nimcp_sparse_tensor_t* tensor, float* values,
    int* row_indices, int* col_indices) { return false; }

int nimcp_sparse_rows(const nimcp_sparse_tensor_t* tensor) { return 0; }
int nimcp_sparse_cols(const nimcp_sparse_tensor_t* tensor) { return 0; }
int nimcp_sparse_nnz(const nimcp_sparse_tensor_t* tensor) { return 0; }
float nimcp_sparse_sparsity(const nimcp_sparse_tensor_t* tensor) { return 0.0f; }

const char* nimcp_sparse_format_name(nimcp_sparse_format_t format)
{
    switch (format) {
        case SPARSE_FORMAT_CSR: return "CSR";
        case SPARSE_FORMAT_CSC: return "CSC";
        case SPARSE_FORMAT_COO: return "COO";
        case SPARSE_FORMAT_BSR: return "BSR";
        case SPARSE_FORMAT_ELL: return "ELL";
        default: return "UNKNOWN";
    }
}

#endif // NIMCP_ENABLE_CUDA
