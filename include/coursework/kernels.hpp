#pragma once
#include <cuda_runtime.h>

// ── Part A1: vector operations
// ────────────────────────────────────────────────
void launch_axpy(
    int n,
    float alpha,
    const float *x,
    float *y,
    cudaStream_t stream = 0); // y = alpha * x + y

void launch_add(
    int n,
    const float *x,
    const float *y,
    float *z,
    cudaStream_t stream = 0); // z = x + y

void launch_copy(
    int n,
    const float *x,
    float *y,
    cudaStream_t stream = 0); // y = x

// ── Part A2: parallel reduction
// ───────────────────────────────────────────────
float gpu_reduce_sum(
        const float *device_x,
        int n,
        float *scratch,
        cudaStream_t stream = 0
    );

// ── Part B: GEMM
// ──────────────────────────────────────────────────────────────
void launch_gemm_naive(
    int M,
    int N,
    int K,
    const float *A,
    const float *B,
    float *C,
    cudaStream_t stream = 0);

void launch_gemm_tiled16(
    int M,
    int N,
    int K,
    const float *A,
    const float *B,
    float *C,
    cudaStream_t stream = 0);
