/**
 * @file test_warp_level_optimizations.cu
 * @brief Warp-level optimization strategies for Mars X201 (warp=64)
 *
 * Explore additional optimization avenues:
 * 1. Different warp reduction strategies
 * 2. Launch bounds optimization
 * 3. Register pressure tuning
 * 4. Memory alignment strategies
 */

#include <iostream>
#include <fstream>
#include <sstream>
#include <vector>
#include <algorithm>

#ifndef WARP_SIZE
#define WARP_SIZE 64
#endif

struct CSRMatrix {
    int numRows, numCols, nnz;
    int* rowPtr;
    int* colIdx;
    float* values;
    int* d_rowPtr;
    int* d_colIdx;
    float* d_values;
};

class GpuTimer {
public:
    GpuTimer() { cudaEventCreate(&start_); cudaEventCreate(&stop_); }
    ~GpuTimer() { cudaEventDestroy(start_); cudaEventDestroy(stop_); }
    void start() { cudaEventRecord(start_, 0); }
    void stop() { cudaEventRecord(stop_, 0); cudaEventSynchronize(stop_); }
    float elapsed_ms() { float ms; cudaEventElapsedTime(&ms, start_, stop_); return ms; }
private:
    cudaEvent_t start_, stop_;
};

bool loadMatrixMarket(const std::string& filename, CSRMatrix& matrix) {
    std::ifstream file(filename);
    if (!file.is_open()) return false;

    std::string line;
    std::getline(file, line);
    while (std::getline(file, line) && line[0] == '%') {}

    std::istringstream iss(line);
    int rows, cols, nnz;
    iss >> rows >> cols >> nnz;

    matrix.numRows = rows;
    matrix.numCols = cols;
    matrix.nnz = nnz;

    std::vector<std::tuple<int, int, float>> entries;
    entries.reserve(nnz);

    while (std::getline(file, line)) {
        if (line.empty() || line[0] == '%') continue;
        std::istringstream iss2(line);
        int r, c;
        float v;
        iss2 >> r >> c >> v;
        entries.push_back({r - 1, c - 1, v});
    }

    std::sort(entries.begin(), entries.end());

    matrix.rowPtr = new int[rows + 1];
    matrix.colIdx = new int[nnz];
    matrix.values = new float[nnz];

    matrix.rowPtr[0] = 0;
    int currentRow = 0;
    for (int i = 0; i < nnz; i++) {
        int r = std::get<0>(entries[i]);
        while (currentRow < r) { currentRow++; matrix.rowPtr[currentRow] = i; }
        matrix.colIdx[i] = std::get<1>(entries[i]);
        matrix.values[i] = std::get<2>(entries[i]);
    }
    while (currentRow < rows) { currentRow++; matrix.rowPtr[currentRow] = nnz; }

    return true;
}

// ==================== Warp Reduction Variants ====================

// Standard tree reduction for 4 threads
__device__ __forceinline__ float warp_reduce_4t(float val) {
    // For 4 threads: reduce using shuffle
    val += __shfl_down_sync(0xffffffffffffffff, val, 2, 4);
    val += __shfl_down_sync(0xffffffffffffffff, val, 1, 4);
    return val;
}

// Alternative: butterfly reduction
__device__ __forceinline__ float warp_reduce_butterfly_4t(float val) {
    // Butterfly pattern for 4 threads
    val += __shfl_xor_sync(0xffffffffffffffff, val, 2, 4);
    val += __shfl_xor_sync(0xffffffffffffffff, val, 1, 4);
    return val;
}

// Use shared memory for reduction (alternative approach)
__device__ __forceinline__ float warp_reduce_smem(float val, int threadInRow) {
    __shared__ float smem[512];  // Max threads per block
    smem[threadIdx.x] = val;
    __syncthreads();

    // Only thread 0 in each row reads all 4 values
    if (threadInRow == 0) {
        int base = (threadIdx.x / 4) * 4;
        return smem[base] + smem[base+1] + smem[base+2] + smem[base+3];
    }
    return val;
}

// ==================== Kernel Variants ====================

// Baseline: tree reduction
template<int BLOCK_SIZE>
__global__ void spmv_tree_reduce(int numRows, const int* __restrict__ rowPtr,
                                  const int* __restrict__ colIdx,
                                  const float* __restrict__ values,
                                  const float* __restrict__ x, float* __restrict__ y) {
    int warpId = threadIdx.x / WARP_SIZE;
    int lane = threadIdx.x % WARP_SIZE;
    int globalWarpId = blockIdx.x * (BLOCK_SIZE / WARP_SIZE) + warpId;

    int baseRow = globalWarpId * 16;
    int rowIdx = lane / 4;
    int threadInRow = lane % 4;
    int row = baseRow + rowIdx;

    if (row >= numRows) return;

    int rowStart = rowPtr[row];
    int rowEnd = rowPtr[row + 1];

    float sum0 = 0, sum1 = 0;
    int idx = rowStart + threadInRow;

    for (; idx + 4 < rowEnd; idx += 8) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
        sum1 += values[idx + 4] * __ldg(&x[colIdx[idx + 4]]);
    }
    for (; idx < rowEnd; idx += 4) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
    }

    float sum = sum0 + sum1;
    sum = warp_reduce_4t(sum);

    if (threadInRow == 0) y[row] = sum;
}

// Butterfly reduction variant
template<int BLOCK_SIZE>
__global__ void spmv_butterfly(int numRows, const int* __restrict__ rowPtr,
                                const int* __restrict__ colIdx,
                                const float* __restrict__ values,
                                const float* __restrict__ x, float* __restrict__ y) {
    int warpId = threadIdx.x / WARP_SIZE;
    int lane = threadIdx.x % WARP_SIZE;
    int globalWarpId = blockIdx.x * (BLOCK_SIZE / WARP_SIZE) + warpId;

    int baseRow = globalWarpId * 16;
    int rowIdx = lane / 4;
    int threadInRow = lane % 4;
    int row = baseRow + rowIdx;

    if (row >= numRows) return;

    int rowStart = rowPtr[row];
    int rowEnd = rowPtr[row + 1];

    float sum0 = 0, sum1 = 0;
    int idx = rowStart + threadInRow;

    for (; idx + 4 < rowEnd; idx += 8) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
        sum1 += values[idx + 4] * __ldg(&x[colIdx[idx + 4]]);
    }
    for (; idx < rowEnd; idx += 4) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
    }

    float sum = sum0 + sum1;
    sum = warp_reduce_butterfly_4t(sum);

    if (threadInRow == 0) y[row] = sum;
}

// Shared memory reduction variant
template<int BLOCK_SIZE>
__global__ void spmv_smem_reduce(int numRows, const int* __restrict__ rowPtr,
                                  const int* __restrict__ colIdx,
                                  const float* __restrict__ values,
                                  const float* __restrict__ x, float* __restrict__ y) {
    __shared__ float smem[BLOCK_SIZE];

    int warpId = threadIdx.x / WARP_SIZE;
    int lane = threadIdx.x % WARP_SIZE;
    int globalWarpId = blockIdx.x * (BLOCK_SIZE / WARP_SIZE) + warpId;

    int baseRow = globalWarpId * 16;
    int rowIdx = lane / 4;
    int threadInRow = lane % 4;
    int row = baseRow + rowIdx;

    if (row >= numRows) return;

    int rowStart = rowPtr[row];
    int rowEnd = rowPtr[row + 1];

    float sum0 = 0, sum1 = 0;
    int idx = rowStart + threadInRow;

    for (; idx + 4 < rowEnd; idx += 8) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
        sum1 += values[idx + 4] * __ldg(&x[colIdx[idx + 4]]);
    }
    for (; idx < rowEnd; idx += 4) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
    }

    float sum = sum0 + sum1;

    // Use shared memory for reduction
    int smemIdx = rowIdx * 4 + threadInRow;
    smem[smemIdx] = sum;
    __syncthreads();

    if (threadInRow == 0) {
        int base = rowIdx * 4;
        y[row] = smem[base] + smem[base+1] + smem[base+2] + smem[base+3];
    }
}

// Launch bounds optimized: more registers per thread
template<int BLOCK_SIZE>
__launch_bounds__(512, 1)  // 1 block per SM for more registers
__global__ void spmv_max_regs(int numRows, const int* __restrict__ rowPtr,
                               const int* __restrict__ colIdx,
                               const float* __restrict__ values,
                               const float* __restrict__ x, float* __restrict__ y) {
    int warpId = threadIdx.x / WARP_SIZE;
    int lane = threadIdx.x % WARP_SIZE;
    int globalWarpId = blockIdx.x * (BLOCK_SIZE / WARP_SIZE) + warpId;

    int baseRow = globalWarpId * 16;
    int rowIdx = lane / 4;
    int threadInRow = lane % 4;
    int row = baseRow + rowIdx;

    if (row >= numRows) return;

    int rowStart = rowPtr[row];
    int rowEnd = rowPtr[row + 1];

    float sum0 = 0, sum1 = 0;
    int idx = rowStart + threadInRow;

    for (; idx + 4 < rowEnd; idx += 8) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
        sum1 += values[idx + 4] * __ldg(&x[colIdx[idx + 4]]);
    }
    for (; idx < rowEnd; idx += 4) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
    }

    float sum = sum0 + sum1;
    sum += __shfl_down_sync(0xffffffffffffffff, sum, 2, 4);
    sum += __shfl_down_sync(0xffffffffffffffff, sum, 1, 4);

    if (threadInRow == 0) y[row] = sum;
}

// No restrict keyword (test impact)
template<int BLOCK_SIZE>
__global__ void spmv_no_restrict(int numRows, const int* rowPtr,
                                  const int* colIdx,
                                  const float* values,
                                  const float* x, float* y) {
    int warpId = threadIdx.x / WARP_SIZE;
    int lane = threadIdx.x % WARP_SIZE;
    int globalWarpId = blockIdx.x * (BLOCK_SIZE / WARP_SIZE) + warpId;

    int baseRow = globalWarpId * 16;
    int rowIdx = lane / 4;
    int threadInRow = lane % 4;
    int row = baseRow + rowIdx;

    if (row >= numRows) return;

    int rowStart = rowPtr[row];
    int rowEnd = rowPtr[row + 1];

    float sum0 = 0, sum1 = 0;
    int idx = rowStart + threadInRow;

    for (; idx + 4 < rowEnd; idx += 8) {
        sum0 += values[idx] * x[colIdx[idx]];
        sum1 += values[idx + 4] * x[colIdx[idx + 4]];
    }
    for (; idx < rowEnd; idx += 4) {
        sum0 += values[idx] * x[colIdx[idx]];
    }

    float sum = sum0 + sum1;
    sum += __shfl_down_sync(0xffffffffffffffff, sum, 2, 4);
    sum += __shfl_down_sync(0xffffffffffffffff, sum, 1, 4);

    if (threadInRow == 0) y[row] = sum;
}

// Direct write (no reduction optimization)
template<int BLOCK_SIZE>
__global__ void spmv_direct_write(int numRows, const int* __restrict__ rowPtr,
                                   const int* __restrict__ colIdx,
                                   const float* __restrict__ values,
                                   const float* __restrict__ x, float* __restrict__ y) {
    int warpId = threadIdx.x / WARP_SIZE;
    int lane = threadIdx.x % WARP_SIZE;
    int globalWarpId = blockIdx.x * (BLOCK_SIZE / WARP_SIZE) + warpId;

    int baseRow = globalWarpId * 16;
    int rowIdx = lane / 4;
    int threadInRow = lane % 4;
    int row = baseRow + rowIdx;

    if (row >= numRows) return;

    int rowStart = rowPtr[row];
    int rowEnd = rowPtr[row + 1];

    float sum0 = 0, sum1 = 0;
    int idx = rowStart + threadInRow;

    for (; idx + 4 < rowEnd; idx += 8) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
        sum1 += values[idx + 4] * __ldg(&x[colIdx[idx + 4]]);
    }
    for (; idx < rowEnd; idx += 4) {
        sum0 += values[idx] * __ldg(&x[colIdx[idx]]);
    }

    float sum = sum0 + sum1;

    // Direct reduction without shuffle
    if (threadInRow == 0) {
        sum += sum;  // Placeholder - actual reduction via shuffle
    }

    sum += __shfl_down_sync(0xffffffffffffffff, sum, 2, 4);
    sum += __shfl_down_sync(0xffffffffffffffff, sum, 1, 4);

    if (threadInRow == 0) y[row] = sum;
}

template<typename KernelFunc>
float runTest(KernelFunc kernel, int gridSize, int blockSize, int iterations,
              const CSRMatrix& matrix, float* d_x, float* d_y) {
    GpuTimer timer;
    float totalTime = 0;

    cudaFuncSetCacheConfig(kernel, cudaFuncCachePreferL1);

    for (int i = 0; i < 10; i++) {
        kernel<<<gridSize, blockSize>>>(matrix.numRows, matrix.d_rowPtr,
                                        matrix.d_colIdx, matrix.d_values, d_x, d_y);
        cudaDeviceSynchronize();
    }

    for (int i = 0; i < iterations; i++) {
        cudaMemset(d_y, 0, matrix.numRows * sizeof(float));
        cudaDeviceSynchronize();
        timer.start();
        kernel<<<gridSize, blockSize>>>(matrix.numRows, matrix.d_rowPtr,
                                        matrix.d_colIdx, matrix.d_values, d_x, d_y);
        cudaDeviceSynchronize();
        timer.stop();
        totalTime += timer.elapsed_ms();
    }

    return totalTime / iterations;
}

int main(int argc, char** argv) {
    printf("=== Warp-Level Optimization Test ===\n");
    printf("WARP_SIZE = %d\n", WARP_SIZE);

    std::string matrixFile = argc > 1 ? argv[1] : "./real_cases/mtx/p0_A";
    int iterations = argc > 2 ? atoi(argv[2]) : 50;

    CSRMatrix matrix;
    if (!loadMatrixMarket(matrixFile, matrix)) {
        std::cerr << "Failed to load matrix: " << matrixFile << "\n";
        return 1;
    }

    printf("Matrix: %d x %d, nnz=%d, avgNnz=%.2f\n\n",
           matrix.numRows, matrix.numCols, matrix.nnz,
           (double)matrix.nnz / matrix.numRows);

    cudaMalloc(&matrix.d_rowPtr, (matrix.numRows + 1) * sizeof(int));
    cudaMalloc(&matrix.d_colIdx, matrix.nnz * sizeof(int));
    cudaMalloc(&matrix.d_values, matrix.nnz * sizeof(float));
    cudaMemcpy(matrix.d_rowPtr, matrix.rowPtr, (matrix.numRows + 1) * sizeof(int), cudaMemcpyHostToDevice);
    cudaMemcpy(matrix.d_colIdx, matrix.colIdx, matrix.nnz * sizeof(int), cudaMemcpyHostToDevice);
    cudaMemcpy(matrix.d_values, matrix.values, matrix.nnz * sizeof(float), cudaMemcpyHostToDevice);

    float* h_x = new float[matrix.numCols];
    for (int i = 0; i < matrix.numCols; i++) h_x[i] = rand() / (float)RAND_MAX;

    float* d_x, *d_y;
    cudaMalloc(&d_x, matrix.numCols * sizeof(float));
    cudaMalloc(&d_y, matrix.numRows * sizeof(float));
    cudaMemcpy(d_x, h_x, matrix.numCols * sizeof(float), cudaMemcpyHostToDevice);

    float peakBW = (WARP_SIZE == 64) ? 1843.0f : 1008.0f;
    size_t dataBytes = (matrix.numRows + 1) * sizeof(int) +
                       matrix.nnz * sizeof(int) +
                       matrix.nnz * sizeof(float) * 2 +
                       matrix.numCols * sizeof(float) +
                       matrix.numRows * sizeof(float);

    int blockSize = 512;
    int rowsPerWarp = WARP_SIZE / 4;
    int gridSize = (matrix.numRows + (blockSize / WARP_SIZE) * rowsPerWarp - 1) /
                   ((blockSize / WARP_SIZE) * rowsPerWarp);

    printf("%-25s %12s %12s\n", "Variant", "Time(ms)", "Util(%)");
    printf("%-25s %12s %12s\n", "-------------------------", "--------", "-------");

    auto printResult = [&](const char* name, float t) {
        float bw = (dataBytes / (t * 1e-3)) / (1024 * 1024 * 1024);
        printf("%-25s %12.3f %11.2f%%\n", name, t, bw / peakBW * 100);
    };

    float t;

    t = runTest(spmv_tree_reduce<512>, gridSize, blockSize, iterations, matrix, d_x, d_y);
    printResult("Tree Reduce", t);

    t = runTest(spmv_butterfly<512>, gridSize, blockSize, iterations, matrix, d_x, d_y);
    printResult("Butterfly Reduce", t);

    t = runTest(spmv_smem_reduce<512>, gridSize, blockSize, iterations, matrix, d_x, d_y);
    printResult("Shared Mem Reduce", t);

    t = runTest(spmv_max_regs<512>, gridSize, blockSize, iterations, matrix, d_x, d_y);
    printResult("Max Registers", t);

    t = runTest(spmv_no_restrict<512>, gridSize, blockSize, iterations, matrix, d_x, d_y);
    printResult("No Restrict", t);

    printf("\n=== Analysis ===\n");
    printf("Testing different warp-level reduction strategies.\n");
    printf("All variants use optimal 4t/row configuration.\n");

    delete[] h_x;
    delete[] matrix.rowPtr;
    delete[] matrix.colIdx;
    delete[] matrix.values;
    cudaFree(matrix.d_rowPtr);
    cudaFree(matrix.d_colIdx);
    cudaFree(matrix.d_values);
    cudaFree(d_x);
    cudaFree(d_y);

    return 0;
}