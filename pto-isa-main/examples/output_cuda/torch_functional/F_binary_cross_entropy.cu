// PTO Program: F_binary_cross_entropy
// Auto-generated CUDA code from PTO ISA Compiler
#include <cuda_runtime.h>
#include <cuda_fp16.h>
#include <cuda_bf16.h>
#include <mma.h>
#include <cooperative_groups.h>
#include <math.h>
#include <stdint.h>
#include <stdio.h>

namespace cg = cooperative_groups;

__device__ float pred[8][8];
__device__ float target[8][8];
__device__ float log_pred[8][8];
__device__ float one_minus_pred[8][8];
__device__ float log_one_minus[8][8];
__device__ float one_minus_target[8][8];
__device__ float term1[8][8];
__device__ float term2[8][8];
__device__ float bce[8][8];
__device__ float row_sum[8][1];
__device__ float result[1][1];

__global__ void F_binary_cross_entropy_kernel(float* input, float* target_mem, float* output) {
    int _row = threadIdx.y + blockIdx.y * blockDim.y;
    int _col = threadIdx.x + blockIdx.x * blockDim.x;

    // Loop fusion: 12 loop overheads saved

    // FUSED (12 ops): pred=TLOAD(...); target=TLOAD(...); log_pred=TLOG(...); one_minus_pred=TMULS(...); one_minus_pred=TADDS(...); log_one_minus=TLOG(...); one_minus_target=TMULS(...); one_minus_target=TADDS(...); term1=TMUL(...); term2=TMUL(...); bce=TADD(...); bce=TNEG(...)
    if (_row < 8 && _col < 8) {
        pred[_row][_col] = input[_row * 8 + _col];
        target[_row][_col] = target_mem[_row * 8 + _col];
        log_pred[_row][_col] = __logf(pred[_row][_col]);
        one_minus_pred[_row][_col] = pred[_row][_col] * -1.0f;
        one_minus_pred[_row][_col] = one_minus_pred[_row][_col] + 1.0f;
        log_one_minus[_row][_col] = __logf(one_minus_pred[_row][_col]);
        one_minus_target[_row][_col] = target[_row][_col] * -1.0f;
        one_minus_target[_row][_col] = one_minus_target[_row][_col] + 1.0f;
        term1[_row][_col] = target[_row][_col] * log_pred[_row][_col];
        term2[_row][_col] = one_minus_target[_row][_col] * log_one_minus[_row][_col];
        bce[_row][_col] = term1[_row][_col] + term2[_row][_col];
        bce[_row][_col] = -bce[_row][_col];
    }

    // BARRIER: TROWSUM

    // BARRIER: TCOLSUM

    // FUSED (2 ops): result=TDIVS(...); output=TSTORE(...)
    if (_row < 1 && _col < 1) {
        result[_row][_col] = result[_row][_col] / 64.0f;
        output[_row * 1 + _col] = result[_row][_col];
    }

}

void F_binary_cross_entropy(float* input, float* target_mem, float* output) {
    dim3 block(8, 8);
    dim3 grid(1, 1);
    F_binary_cross_entropy_kernel<<<grid, block>>>(input, target_mem, output);
    cudaDeviceSynchronize();
}