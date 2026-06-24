/**
 * Copyright (c) 2026 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

#ifndef GEMM_BATCHED_EX_NPU_WRAPPER_H
#define GEMM_BATCHED_EX_NPU_WRAPPER_H

#include <algorithm>
#include <cstdint>
#include <cstring>
#include <vector>

#include "acl/acl.h"
#include "cann_ops_blas.h"
#include "gemm_batched_ex_param.h"

// ── Helper: allocate device memory and copy host→device ──
inline aclblasStatus_t AllocateAndCopyBatchedDevice(void** devPtr, const void* hostPtr, size_t bytes)
{
    *devPtr = nullptr;
    if (hostPtr == nullptr || bytes == 0) {
        return ACLBLAS_STATUS_SUCCESS;
    }
    aclError ret = aclrtMalloc(devPtr, bytes, ACL_MEM_MALLOC_HUGE_FIRST);
    if (ret != ACL_SUCCESS) {
        *devPtr = nullptr;
        return ACLBLAS_STATUS_ALLOC_FAILED;
    }
    ret = aclrtMemcpy(*devPtr, bytes, hostPtr, bytes, ACL_MEMCPY_HOST_TO_DEVICE);
    if (ret != ACL_SUCCESS) {
        aclrtFree(*devPtr);
        *devPtr = nullptr;
        return ACLBLAS_STATUS_INTERNAL_ERROR;
    }
    return ACLBLAS_STATUS_SUCCESS;
}

// ── Context for batched device resources ──
struct BatchedGemmDeviceCtx {
    std::vector<void*> dAarray;
    std::vector<void*> dBarray;
    std::vector<void*> dCarray;
    void* dAPtrArray = nullptr;
    void* dBPtrArray = nullptr;
    void* dCPtrArray = nullptr;

    void Init(int batchCount)
    {
        dAarray.assign(batchCount, nullptr);
        dBarray.assign(batchCount, nullptr);
        dCarray.assign(batchCount, nullptr);
    }

    void Cleanup()
    {
        for (size_t i = 0; i < dAarray.size(); i++) {
            if (dAarray[i]) aclrtFree(dAarray[i]);
            if (dBarray[i]) aclrtFree(dBarray[i]);
            if (dCarray[i]) aclrtFree(dCarray[i]);
        }
        if (dAPtrArray) aclrtFree(dAPtrArray);
        if (dBPtrArray) aclrtFree(dBPtrArray);
        if (dCPtrArray) aclrtFree(dCPtrArray);
    }
};

// ── Helper: compute device buffer sizes for batched A, B, C ──
struct BatchedDeviceBufferSizes {
    size_t aBytes;
    size_t bBytes;
    size_t cBytes;
};

inline BatchedDeviceBufferSizes ComputeBatchedBufferSizes(
    aclblasOperation_t transA, aclblasOperation_t transB,
    int m, int n, int k, int lda, int ldb, int ldc,
    aclDataType Atype, aclDataType Btype, aclDataType Ctype)
{
    const int physColsA = (transA == ACLBLAS_OP_N) ? k : m;
    const int physColsB = (transB == ACLBLAS_OP_N) ? n : k;
    const int allocLda = std::max(1, lda);
    const int allocLdb = std::max(1, ldb);
    const int allocLdc = std::max(1, ldc);
    const int elemSizeA = aclDataTypeSize(Atype);
    const int elemSizeB = aclDataTypeSize(Btype);
    const int elemSizeC = aclDataTypeSize(Ctype);
    BatchedDeviceBufferSizes sizes;
    sizes.aBytes = static_cast<size_t>(allocLda) * std::max(1, physColsA) * elemSizeA;
    sizes.bBytes = static_cast<size_t>(allocLdb) * std::max(1, physColsB) * elemSizeB;
    sizes.cBytes = static_cast<size_t>(allocLdc) * std::max(1, n) * elemSizeC;
    return sizes;
}

// ── Helper: allocate all batched device memory (data buffers + pointer arrays) ──
inline aclblasStatus_t AllocateBatchedGemmDevice(
    BatchedGemmDeviceCtx& ctx,
    const void* const Aarray[], const void* const Barray[], void* const Carray[],
    int batchCount, int k,
    aclblasOperation_t transA, aclblasOperation_t transB,
    int m, int n, int lda, int ldb, int ldc,
    aclDataType Atype, aclDataType Btype, aclDataType Ctype)
{
    ctx.Init(batchCount);

    auto sizes = ComputeBatchedBufferSizes(transA, transB, m, n, k, lda, ldb, ldc, Atype, Btype, Ctype);

    // Allocate data buffers for each batch
    // When k <= 0, A and B have zero size and are skipped; C is always allocated.
    for (int i = 0; i < batchCount; i++) {
        if (k > 0 && Aarray && Aarray[i]) {
            aclblasStatus_t ret = AllocateAndCopyBatchedDevice(&ctx.dAarray[i], Aarray[i], sizes.aBytes);
            if (ret != ACLBLAS_STATUS_SUCCESS) return ret;
        }
        if (k > 0 && Barray && Barray[i]) {
            aclblasStatus_t ret = AllocateAndCopyBatchedDevice(&ctx.dBarray[i], Barray[i], sizes.bBytes);
            if (ret != ACLBLAS_STATUS_SUCCESS) return ret;
        }
        if (Carray && Carray[i]) {
            aclblasStatus_t ret = AllocateAndCopyBatchedDevice(&ctx.dCarray[i], Carray[i], sizes.cBytes);
            if (ret != ACLBLAS_STATUS_SUCCESS) return ret;
        }
    }

    // Allocate pointer arrays
    size_t ptrBytes = static_cast<size_t>(batchCount) * sizeof(void*);
    if (k > 0 && Aarray) {
        aclblasStatus_t ret = AllocateAndCopyBatchedDevice(&ctx.dAPtrArray, ctx.dAarray.data(), ptrBytes);
        if (ret != ACLBLAS_STATUS_SUCCESS) return ret;
    }
    if (k > 0 && Barray) {
        aclblasStatus_t ret = AllocateAndCopyBatchedDevice(&ctx.dBPtrArray, ctx.dBarray.data(), ptrBytes);
        if (ret != ACLBLAS_STATUS_SUCCESS) return ret;
    }
    if (Carray) {
        aclblasStatus_t ret = AllocateAndCopyBatchedDevice(&ctx.dCPtrArray, ctx.dCarray.data(), ptrBytes);
        if (ret != ACLBLAS_STATUS_SUCCESS) return ret;
    }
    return ACLBLAS_STATUS_SUCCESS;
}

// ── Helper: copy batched results from device to host ──
inline aclblasStatus_t CopyBatchResultsBack(
    void* const Carray[], const std::vector<void*>& dCarray,
    int batchCount, size_t cBytes)
{
    if (Carray == nullptr) return ACLBLAS_STATUS_SUCCESS;
    for (int i = 0; i < batchCount; i++) {
        if (Carray[i] != nullptr && dCarray[i] != nullptr) {
            aclError aclRet = aclrtMemcpy(Carray[i], cBytes, dCarray[i], cBytes, ACL_MEMCPY_DEVICE_TO_HOST);
            if (aclRet != ACL_SUCCESS) return ACLBLAS_STATUS_INTERNAL_ERROR;
        }
    }
    return ACLBLAS_STATUS_SUCCESS;
}

// ── Implementation: execute batched GEMM with pre-allocated device context ──
inline aclblasStatus_t ExecuteBatchedGemmImpl(
    BatchedGemmDeviceCtx& ctx,
    aclblasHandle_t handle,
    aclblasOperation_t transA, aclblasOperation_t transB,
    int m, int n, int k,
    const void* alpha,
    const void* const Aarray[], aclDataType Atype, int lda,
    const void* const Barray[], aclDataType Btype, int ldb,
    const void* beta,
    void* const Carray[], aclDataType Ctype, int ldc,
    int batchCount, aclblasComputeType_t computeType, aclblasGemmAlgo_t algo)
{
    const void* const* dAPtr = ctx.dAPtrArray ? static_cast<const void* const*>(ctx.dAPtrArray) : nullptr;
    const void* const* dBPtr = ctx.dBPtrArray ? static_cast<const void* const*>(ctx.dBPtrArray) : nullptr;
    void* const* dCPtr = ctx.dCPtrArray ? static_cast<void* const*>(ctx.dCPtrArray) : nullptr;

    aclblasStatus_t ret = aclblasGemmBatchedEx(
        handle, transA, transB, m, n, k, alpha,
        dAPtr ? dAPtr : Aarray, Atype, lda,
        dBPtr ? dBPtr : Barray, Btype, ldb,
        beta, dCPtr ? dCPtr : Carray, Ctype, ldc,
        batchCount, computeType, algo);
    aclError syncRet = aclrtSynchronizeDevice();
    if (syncRet != ACL_SUCCESS)
        return ACLBLAS_STATUS_INTERNAL_ERROR;

    if (ret != ACLBLAS_STATUS_SUCCESS || Carray == nullptr) return ret;

    auto sizes = ComputeBatchedBufferSizes(transA, transB, m, n, k, lda, ldb, ldc, Atype, Btype, Ctype);
    return CopyBatchResultsBack(Carray, ctx.dCarray, batchCount, sizes.cBytes);
}

// ── NPU wrapper for aclblasGemmBatchedEx ──
// Handles device memory allocation for each batch, pointer array setup,
// H2D/D2H transfers, and kernel invocation.
// NULLPTR inputs are passed through without device allocation (for error-path testing).
// aclblasGemmBatchedEx is declared in cann_ops_blas.h with C linkage; link via libops_blas.so.
inline aclblasStatus_t aclblasGemmBatchedEx_npu(
    aclblasHandle_t handle,
    aclblasOperation_t transA, aclblasOperation_t transB,
    int m, int n, int k,
    const void* alpha,
    const void* const Aarray[], aclDataType Atype, int lda,
    const void* const Barray[], aclDataType Btype, int ldb,
    const void* beta,
    void* const Carray[], aclDataType Ctype, int ldc,
    int batchCount,
    aclblasComputeType_t computeType,
    aclblasGemmAlgo_t algo = ACLBLAS_GEMM_DEFAULT)
{
    // Pass through for error-path or empty-matrix testing
    if (handle == nullptr || batchCount <= 0 || m <= 0 || n <= 0) {
        return aclblasGemmBatchedEx(
            handle, transA, transB, m, n, k,
            alpha, Aarray, Atype, lda, Barray, Btype, ldb,
            beta, Carray, Ctype, ldc, batchCount, computeType, algo);
    }

    BatchedGemmDeviceCtx ctx;
    aclblasStatus_t allocRet = AllocateBatchedGemmDevice(
        ctx, Aarray, Barray, Carray, batchCount, k,
        transA, transB, m, n, lda, ldb, ldc, Atype, Btype, Ctype);
    if (allocRet != ACLBLAS_STATUS_SUCCESS) {
        ctx.Cleanup();
        return allocRet;
    }

    aclblasStatus_t ret = ExecuteBatchedGemmImpl(
        ctx, handle, transA, transB, m, n, k,
        alpha, Aarray, Atype, lda, Barray, Btype, ldb,
        beta, Carray, Ctype, ldc, batchCount, computeType, algo);
    ctx.Cleanup();
    return ret;
}

#endif // GEMM_BATCHED_EX_NPU_WRAPPER_H
