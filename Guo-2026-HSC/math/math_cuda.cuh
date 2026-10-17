#pragma once
#include <cuda.h>
#include <cuda_runtime.h>
#include "svd3_cuda.cuh"
#include <stdio.h>
#include <thrust/execution_policy.h>
#include <thrust/inner_product.h>
#include <thrust/device_ptr.h>
#include <thrust/device_vector.h>
#include "epsilon_cuda.cuh"
#include "kernel_computations/inner_product_cuda.cuh"
#include <Eigen/Core>

#ifndef PI
#define PI 3.14159265358979323846
#endif

#ifndef INF
#define INF 1e20
#endif

template <class T>
__host__ __device__ __forceinline__
T
abs(T x) { return x < 0.0 ? -x : x; }

template <class T>
__host__ __device__ __forceinline__
T
max(T x, T y) { return x > y ? x : y; }

template <class T>
__host__ __device__ __forceinline__
T
min(T x, T y) { return x < y ? x : y; }

template <class T>
__host__ __device__ __forceinline__
T
max(T x, T y, T z) { return x > y ? (x > z ? x : z) : (y > z ? y : z); }

template <class T>
__host__ __device__ __forceinline__
T
min(T x, T y, T z) { return x < y ? (x < z ? x : z) : (y < z ? y : z); }

template <class T>
__host__ __device__ __forceinline__
T
max(T w, T x, T y, T z) { return max<T>(max<T>(w, x), max<T>(y, z)); }

template <class T>
__host__ __device__ __forceinline__
T
min(T w, T x, T y, T z) { return min<T>(min<T>(w, x), min<T>(y, z)); }

template <class T>
__host__ __device__ __forceinline__
T clamp_small(T x)
{
    if (abs<T>(x) < EPSILON)
    {
        if (x >= 0) return EPSILON;
        else return -EPSILON;
    }
    return x;
}

template <class T>
__host__ __device__ __forceinline__ void negate(T* x, unsigned int n)
{
    for (unsigned int i = 0; i < n; ++i)
    {
        x[i] = -x[i];
    }
}

template <class T>
__host__ __device__ __forceinline__ int magnitude(T x)
{
    return int(floor(log10(abs<T>(x))));
}

template <class T>
__host__ __device__ __forceinline__
T
clamp(T a, T minVal, T maxVal) { return min(max(minVal, a), maxVal); }

template <typename T>
__host__ __device__ T sgn(const T& x) { return x < 0 ? -1 : 1; }

template <class T>
__host__ __device__ __forceinline__ void vecCopy(T *X, const T *A, int n)
{
    for (int i = 0; i < n; ++i)
        X[i] = A[i];
}

template <class T>
__host__ __device__ __forceinline__ void vecAdd(T* X, const T* A, const T* B, int n)
{
    for (int i = 0; i < n; ++i)
        X[i] = A[i] + B[i];
}

template <class T>
__host__ __device__ __forceinline__ void vecSubs(T* X, const T* A, const T* B, int n)
{
    for (int i = 0; i < n; ++i)
        X[i] = A[i] - B[i];
}

template <class T>
__host__ __device__ __forceinline__ void vecAdd3(T* X, const T* A, const T* B)
{
    X[0] = A[0] + B[0];
    X[1] = A[1] + B[1];
    X[2] = A[2] + B[2];
}

template <class T>
__host__ __device__ __forceinline__ void vecSubs3(T* X, const T* A, const T* B)
{
    X[0] = A[0] - B[0];
    X[1] = A[1] - B[1];
    X[2] = A[2] - B[2];
}

template <class T>
__host__ __device__ __forceinline__ void vecMul(T* X, const T a, const T* B, int n)
{
    for (int i = 0; i < n; ++i)
        X[i] = a * B[i];
}

template <class T>
__host__ __device__ __forceinline__ void vecMul(T* X, const T a, int n)
{
    for (int i = 0; i < n; ++i)
        X[i] = a * X[i];
}

template <class T>
__host__ __device__ __forceinline__ void vecMul3(T* X, const T* A, const T* B)
{
    X[0] = A[0] * B[0];
    X[1] = A[1] * B[1];
    X[2] = A[2] * B[2];
}

template <class T>
__host__ __device__ __forceinline__ void vecMul3(T* X, const T A, const T* B)
{
    X[0] = A * B[0];
    X[1] = A * B[1];
    X[2] = A * B[2];
}

template <class T>
__host__ __device__ __forceinline__ void vecMul3(T* X, const T A)
{
    X[0] = A * X[0];
    X[1] = A * X[1];
    X[2] = A * X[2];
}
template <class T>
__host__ __device__ __forceinline__ void vecvecT(T* X, const T* v, const int n)
{
    for (int i = 0; i < n; ++i)
        for (int j = 0; j < n; ++j)
            X[n * i + j] = v[i] * v[j];
}

template <class T>
__host__ __device__ __forceinline__ void vecvecT(T* X, const T* v0, const T* v1, const int m, const int n)
{
    for (int i = 0; i < m; ++i)
        for (int j = 0; j < n; ++j)
            X[n * i + j] = v0[i] * v1[j];
}

template <class T>
__host__ __device__ __forceinline__ void cross3(T* result, const T* vec1, const T* vec2)
{
    result[0] = vec1[1] * vec2[2] - vec2[1] * vec1[2];
    result[1] = -vec1[0] * vec2[2] + vec2[0] * vec1[2];
    result[2] = vec1[0] * vec2[1] - vec2[0] * vec1[1];
}

template <class T>
__host__ __device__ __forceinline__ void dot3(T& result, const T* vec1, const T* vec2)
{
    result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec1[i] * vec2[i];
}

template <class T>
__host__ __device__ __forceinline__ T dot3(const T* vec1, const T* vec2)
{
    T result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec1[i] * vec2[i];
    return result;
}

template <class T>
__host__ __device__ __forceinline__ void norm3(T* result, const T* vec)
{
    T one_over_length = 0.0;
    for (int i = 0; i < 3; ++i)
        one_over_length += vec[i] * vec[i];
    if (one_over_length < EPSILON)
    {
        for (int i = 0; i < 3; ++i)
            result[i] = 0.;
        printf("norm3 error\n");
        return;
    }
    one_over_length = 1.0 / sqrt(one_over_length);
    for (int i = 0; i < 3; ++i)
        result[i] = vec[i] * one_over_length;
}

template <class T>
__host__ __device__ __forceinline__ void norm3length(T* result, T& length, const T* vec)
{
    T one_over_length = 0.0;
    for (int i = 0; i < 3; ++i)
        one_over_length += vec[i] * vec[i];
    length = sqrt(one_over_length);
    one_over_length = 1.0 / length;
    for (int i = 0; i < 3; ++i)
        result[i] = vec[i] * one_over_length;
}

template <class T>
__host__ __device__ __forceinline__ void len3(T& result, const T* vec)
{
    result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    result = sqrt(result);
}

template <class T>
__host__ __device__ __forceinline__
T len3(const T* vec)
{
    T result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    result = sqrt(result);
    return result;
}

template <class T>
__host__ __device__ __forceinline__
T len3(const T* vec0, const T* vec1)
{
    T result = 0.0;
    T vec[3]; vecSubs3<T>(vec, vec0, vec1);
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    result = sqrt(result);
    return result;
}

template <class T>
__host__ __device__ __forceinline__
T lenSq3(const T* vec0, const T* vec1)
{
    T result = 0.0;
    T vec[3]; vecSubs3<T>(vec, vec0, vec1);
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    return result;
}

template <class T>
__host__ __device__ __forceinline__ void dist3(T& result, const T* vec1, const T* vec2)
{
    T vec[3];
    vecSubs3<T>(vec, vec1, vec2);
    result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    result = sqrt(result);
}

template <class T>
__host__ __device__ __forceinline__ T dist3(const T* vec1, const T* vec2)
{
    T vec[3];
    vecSubs3<T>(vec, vec1, vec2);
    T result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    result = sqrt(result);
    return result;
}

template <class T>
__host__ __device__ __forceinline__ void normSquared3(T& result, const T* vec)
{
    result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
}

template <class T>
__host__ __device__ __forceinline__
T normSquared3(const T* vec)
{
    T result = 0.0;
    for (int i = 0; i < 3; ++i)
        result += vec[i] * vec[i];
    return result;
}

template <class T>
__host__ __device__ __forceinline__ void normSquared3(T& result, const T* vec0, const T* vec1)
{
    result = 0.0;
    for (int i = 0; i < 3; ++i)
    {
        T x = vec0[i] - vec1[i];
        result += x * x;
    }
    return result;
}

template <class T>
__host__ __device__ __forceinline__
T normSquared3(const T* vec0, const T* vec1)
{
    T result = 0.0;
    for (int i = 0; i < 3; ++i)
    {
        T x = vec0[i] - vec1[i];
        result += x * x;
    }
    return result;
}

template <class T>
__host__ __device__ __forceinline__ void normSquared(T& result, const T* vec, const unsigned int N)
{
    result = 0.0;
    for (int i = 0; i < N; ++i)
        result += vec[i] * vec[i];
}

template <class T>
__host__ __device__ __forceinline__ void norm3InPlace(T* vec)
{
    T one_over_length = 0;
    for (int i = 0; i < 3; ++i)
        one_over_length += vec[i] * vec[i];
    if (one_over_length == 0.)
    {
        //printf("norm3InPlace<T>::bad_length\n");
        vec[0] = 0.;
        vec[1] = 0.;
        vec[2] = 0.;
        return;
    }
    one_over_length = 1.0 / sqrt(one_over_length);
    for (int i = 0; i < 3; ++i)
        vec[i] = vec[i] * one_over_length;
}

template <class T>
__host__ __device__ __forceinline__ void matVec3(T* result, T* mat, T* vec)
{
    result[0] = mat[0] * vec[0] + mat[1] * vec[1] + mat[2] * vec[2];
    result[1] = mat[3] * vec[0] + mat[4] * vec[1] + mat[5] * vec[2];
    result[2] = mat[6] * vec[0] + mat[7] * vec[1] + mat[8] * vec[2];
}

template <class T>
__host__ __device__ __forceinline__ void matTVec3(T* result, T* mat, T* vec)
{
    result[0] = mat[0] * vec[0] + mat[3] * vec[1] + mat[6] * vec[2];
    result[1] = mat[1] * vec[0] + mat[4] * vec[1] + mat[7] * vec[2];
    result[2] = mat[2] * vec[0] + mat[5] * vec[1] + mat[8] * vec[2];
}

// Given an input vector v, find a unit vector that is orthogonal to it
template <class T>
__host__ __device__ __forceinline__ void findOrthonormalVector3(T* result, const T* vec)
{
    // find smallest abs component of v
    int smallestIndex = 0;
    for (int dim = 1; dim < 3; ++dim)
        if (abs(vec[dim]) < abs(vec[smallestIndex]))
            smallestIndex = dim;

    T axis[3] = { 0.0, 0.0, 0.0 };
    axis[smallestIndex] = 1.0;

    T t[3];
    cross3<T>(t, vec, axis);
    norm3<T>(result, t);
}

template <class T>
__host__ __device__ __forceinline__ void matInv3(T* inv_X, const T* X)
{
    inv_X[0] = X[4] * X[8] - X[5] * X[7];
    inv_X[1] = -X[1] * X[8] + X[2] * X[7];
    inv_X[2] = X[1] * X[5] - X[2] * X[4];
    inv_X[3] = -X[3] * X[8] + X[5] * X[6];
    inv_X[4] = X[0] * X[8] - X[2] * X[6];
    inv_X[5] = -X[0] * X[5] + X[2] * X[3];
    inv_X[6] = X[3] * X[7] - X[4] * X[6];
    inv_X[7] = -X[0] * X[7] + X[1] * X[6];
    inv_X[8] = X[0] * X[4] - X[1] * X[3];
    T J = X[0] * inv_X[0] + X[3] * inv_X[1] + X[6] * inv_X[2];
    // if (J < FLT_MIN)
    //{
    //     //printf("not invertible, %f %f %f %f %f %f %f %f %f\n", X[0], X[1], X[2], X[3], X[4], X[5], X[6], X[7], X[8]);
    //     //return;
    //     for (unsigned int i = 0; i < 3; ++i) for (unsigned int j = 0; j < 3; ++j)
    //     {
    //         if (i == j)
    //             inv_X[3 * i + j] = 1.0;
    //         else
    //             inv_X[3 * i + j] = 0.0;
    //         //printf("%f ", X[3 * i + j]);
    //     }
    //     //printf("\n");
    //     return;
    // }
    T inv_J = 1.0 / J;
    for (int i = 0; i < 9; i++)
        inv_X[i] *= inv_J;
}

template <class T>
__host__ __device__ __forceinline__ void matInv2(T* inv_X, const T* X)
{
    T J = X[0] * X[3] - X[1] * X[2];
    T inv_J = 1. / J;
    inv_X[0] = X[3] * inv_J;
    inv_X[1] = -X[1] * inv_J;
    inv_X[2] = -X[2] * inv_J;
    inv_X[3] = X[0] * inv_J;
}

template <class T>
__host__ __device__ __forceinline__ void matMul3(T* X, const T* A, const T* B)
{
    X[0] = A[0] * B[0] + A[1] * B[3] + A[2] * B[6];
    X[1] = A[0] * B[1] + A[1] * B[4] + A[2] * B[7];
    X[2] = A[0] * B[2] + A[1] * B[5] + A[2] * B[8];
    X[3] = A[3] * B[0] + A[4] * B[3] + A[5] * B[6];
    X[4] = A[3] * B[1] + A[4] * B[4] + A[5] * B[7];
    X[5] = A[3] * B[2] + A[4] * B[5] + A[5] * B[8];
    X[6] = A[6] * B[0] + A[7] * B[3] + A[8] * B[6];
    X[7] = A[6] * B[1] + A[7] * B[4] + A[8] * B[7];
    X[8] = A[6] * B[2] + A[7] * B[5] + A[8] * B[8];
}

template <class T>
__host__ __device__ __forceinline__ void matMul3(T* X, const T a, const T* B)
{
    for (int i = 0; i < 9; ++i)
        X[i] = a * B[i];
}

template <class T>
__host__ __device__ __forceinline__ void matSubs3(T* X, const T* A, const T* B)
{
    for (int i = 0; i < 9; ++i)
        X[i] = A[i] - B[i];
}

// X = (AB)^T
template <class T>
__host__ __device__ __forceinline__ void matMul3T(T* X, const T* A, const T* B)
{
    X[0] = A[0] * B[0] + A[1] * B[3] + A[2] * B[6];
    X[3] = A[0] * B[1] + A[1] * B[4] + A[2] * B[7];
    X[6] = A[0] * B[2] + A[1] * B[5] + A[2] * B[8];
    X[1] = A[3] * B[0] + A[4] * B[3] + A[5] * B[6];
    X[4] = A[3] * B[1] + A[4] * B[4] + A[5] * B[7];
    X[7] = A[3] * B[2] + A[4] * B[5] + A[5] * B[8];
    X[2] = A[6] * B[0] + A[7] * B[3] + A[8] * B[6];
    X[5] = A[6] * B[1] + A[7] * B[4] + A[8] * B[7];
    X[8] = A[6] * B[2] + A[7] * B[5] + A[8] * B[8];
}

template <class T>
__host__ __device__ __forceinline__ void matTMul3(T* X, const T* A, const T* B)
{
    X[0] = A[0] * B[0] + A[3] * B[3] + A[6] * B[6];
    X[1] = A[0] * B[1] + A[3] * B[4] + A[6] * B[7];
    X[2] = A[0] * B[2] + A[3] * B[5] + A[6] * B[8];
    X[3] = A[1] * B[0] + A[4] * B[3] + A[7] * B[6];
    X[4] = A[1] * B[1] + A[4] * B[4] + A[7] * B[7];
    X[5] = A[1] * B[2] + A[4] * B[5] + A[7] * B[8];
    X[6] = A[2] * B[0] + A[5] * B[3] + A[8] * B[6];
    X[7] = A[2] * B[1] + A[5] * B[4] + A[8] * B[7];
    X[8] = A[2] * B[2] + A[5] * B[5] + A[8] * B[8];
}

template <class T>
__host__ __device__ __forceinline__ void matMulT3(T* X, const T* A, const T* B)
{
    X[0] = A[0] * B[0] + A[1] * B[1] + A[2] * B[2];
    X[1] = A[0] * B[3] + A[1] * B[4] + A[2] * B[5];
    X[2] = A[0] * B[6] + A[1] * B[7] + A[2] * B[8];
    X[3] = A[3] * B[0] + A[4] * B[1] + A[5] * B[2];
    X[4] = A[3] * B[3] + A[4] * B[4] + A[5] * B[5];
    X[5] = A[3] * B[6] + A[4] * B[7] + A[5] * B[8];
    X[6] = A[6] * B[0] + A[7] * B[1] + A[8] * B[2];
    X[7] = A[6] * B[3] + A[7] * B[4] + A[8] * B[5];
    X[8] = A[6] * B[6] + A[7] * B[7] + A[8] * B[8];
}

template <class T>
__host__ __device__ __forceinline__ void swap(T& x, T& y)
{
    T t = x;
    x = y;
    y = t;
}

template <class T>
__host__ __device__ __forceinline__ void matSquareTransInPlace(T* X, int n) // transpose only square matrix
{
    for (int i = 0; i < n; ++i)
        for (int j = i + 1; j < n; ++j)
        {
            swap(X[n * i + j], X[n * j + i]);
        }
}

template <class T>
__host__ __device__ __forceinline__ void det2(T& det_X, const T* X)
{
    det_X = X[0] * X[3] - X[1] * X[2];
}

template <class T>
__host__ __device__ __forceinline__ T det2(const T* X)
{
    T det_X;
    det2<T>(det_X, X);
    return det_X;
}

template <class T>
__host__ __device__ __forceinline__ void det3(T& det_X, const T* X)
{
    det_X = X[0] * X[4] * X[8] - X[0] * X[5] * X[7] - X[1] * X[3] * X[8] + X[1] * X[5] * X[6] + X[2] * X[3] * X[7] - X[2] * X[4] * X[6];
}

template <class T>
__host__ __device__ __forceinline__ T det3(const T* X)
{
    T det_X;
    det3<T>(det_X, X);
    return det_X;
}

template <class T>
__host__ __device__ __forceinline__ void svd3_cuda(T* U, T* D, T* V, const T* X)
{
    T _[9];
    svd<T>(X[0], X[1], X[2], X[3], X[4], X[5], X[6], X[7], X[8],
        U[0], U[1], U[2], U[3], U[4], U[5], U[6], U[7], U[8],
        D[0], _[1], _[2], _[3], D[1], _[5], _[6], _[7], D[2],
        V[0], V[1], V[2], V[3], V[4], V[5], V[6], V[7], V[8]);
}

template <class T>
__host__ __device__ __forceinline__ void svd3rv_cuda(T* U, T* D, T* V, const T* X) // rotation invariant svd
{
    svd3_cuda<T>(U, D, V, X);
    T L[9] = { 1.0, 0.0, 0.0, 0.0, 1.0, 0.0, 0.0, 0.0, 1.0 };
    T UVT[9];
    matMulT3<T>(UVT, U, V);
    T detUVT;
    det3<T>(detUVT, UVT);
    L[8] = detUVT;
    T detU, detV;
    det3<T>(detU, U);
    det3<T>(detV, V);

    if (detU < 0.0 && detV > 0.0)
    {
        T _U[9];
        matMul3<T>(_U, U, L);
        for (int i = 0; i < 9; ++i)
            U[i] = _U[i];
    }
    if (detU > 0.0 && detV < 0.0)
    {
        T _V[9];
        matMul3<T>(_V, V, L);
        for (int i = 0; i < 9; ++i)
            V[i] = _V[i];
    }

    D[2] = D[2] * L[8];
}

template <class T>
__host__ __device__ __forceinline__ void matUXVT3(T* R, const T* U, const T* X, const T* V)
{
    R[0] = V[0] * (U[0] * X[0] + U[1] * X[3] + U[2] * X[6]) + V[1] * (U[0] * X[1] + U[1] * X[4] + U[2] * X[7]) + V[2] * (U[0] * X[2] + U[1] * X[5] + U[2] * X[8]);
    R[1] = V[3] * (U[0] * X[0] + U[1] * X[3] + U[2] * X[6]) + V[4] * (U[0] * X[1] + U[1] * X[4] + U[2] * X[7]) + V[5] * (U[0] * X[2] + U[1] * X[5] + U[2] * X[8]);
    R[2] = V[6] * (U[0] * X[0] + U[1] * X[3] + U[2] * X[6]) + V[7] * (U[0] * X[1] + U[1] * X[4] + U[2] * X[7]) + V[8] * (U[0] * X[2] + U[1] * X[5] + U[2] * X[8]);
    R[3] = V[0] * (U[3] * X[0] + U[4] * X[3] + U[5] * X[6]) + V[1] * (U[3] * X[1] + U[4] * X[4] + U[5] * X[7]) + V[2] * (U[3] * X[2] + U[4] * X[5] + U[5] * X[8]);
    R[4] = V[3] * (U[3] * X[0] + U[4] * X[3] + U[5] * X[6]) + V[4] * (U[3] * X[1] + U[4] * X[4] + U[5] * X[7]) + V[5] * (U[3] * X[2] + U[4] * X[5] + U[5] * X[8]);
    R[5] = V[6] * (U[3] * X[0] + U[4] * X[3] + U[5] * X[6]) + V[7] * (U[3] * X[1] + U[4] * X[4] + U[5] * X[7]) + V[8] * (U[3] * X[2] + U[4] * X[5] + U[5] * X[8]);
    R[6] = V[0] * (U[6] * X[0] + U[7] * X[3] + U[8] * X[6]) + V[1] * (U[6] * X[1] + U[7] * X[4] + U[8] * X[7]) + V[2] * (U[6] * X[2] + U[7] * X[5] + U[8] * X[8]);
    R[7] = V[3] * (U[6] * X[0] + U[7] * X[3] + U[8] * X[6]) + V[4] * (U[6] * X[1] + U[7] * X[4] + U[8] * X[7]) + V[5] * (U[6] * X[2] + U[7] * X[5] + U[8] * X[8]);
    R[8] = V[6] * (U[6] * X[0] + U[7] * X[3] + U[8] * X[6]) + V[7] * (U[6] * X[1] + U[7] * X[4] + U[8] * X[7]) + V[8] * (U[6] * X[2] + U[7] * X[5] + U[8] * X[8]);
}

template <class T>
__host__ __device__ __forceinline__ void matUTXV3(T* R, const T* U, const T* X, const T* V)
{
    R[0] = V[0] * (U[0] * X[0] + U[3] * X[3] + U[6] * X[6]) + V[3] * (U[0] * X[1] + U[3] * X[4] + U[6] * X[7]) + V[6] * (U[0] * X[2] + U[3] * X[5] + U[6] * X[8]);
    R[1] = V[1] * (U[0] * X[0] + U[3] * X[3] + U[6] * X[6]) + V[4] * (U[0] * X[1] + U[3] * X[4] + U[6] * X[7]) + V[7] * (U[0] * X[2] + U[3] * X[5] + U[6] * X[8]);
    R[2] = V[2] * (U[0] * X[0] + U[3] * X[3] + U[6] * X[6]) + V[5] * (U[0] * X[1] + U[3] * X[4] + U[6] * X[7]) + V[8] * (U[0] * X[2] + U[3] * X[5] + U[6] * X[8]);
    R[3] = V[0] * (U[1] * X[0] + U[4] * X[3] + U[7] * X[6]) + V[3] * (U[1] * X[1] + U[4] * X[4] + U[7] * X[7]) + V[6] * (U[1] * X[2] + U[4] * X[5] + U[7] * X[8]);
    R[4] = V[1] * (U[1] * X[0] + U[4] * X[3] + U[7] * X[6]) + V[4] * (U[1] * X[1] + U[4] * X[4] + U[7] * X[7]) + V[7] * (U[1] * X[2] + U[4] * X[5] + U[7] * X[8]);
    R[5] = V[2] * (U[1] * X[0] + U[4] * X[3] + U[7] * X[6]) + V[5] * (U[1] * X[1] + U[4] * X[4] + U[7] * X[7]) + V[8] * (U[1] * X[2] + U[4] * X[5] + U[7] * X[8]);
    R[6] = V[0] * (U[2] * X[0] + U[5] * X[3] + U[8] * X[6]) + V[3] * (U[2] * X[1] + U[5] * X[4] + U[8] * X[7]) + V[6] * (U[2] * X[2] + U[5] * X[5] + U[8] * X[8]);
    R[7] = V[1] * (U[2] * X[0] + U[5] * X[3] + U[8] * X[6]) + V[4] * (U[2] * X[1] + U[5] * X[4] + U[8] * X[7]) + V[7] * (U[2] * X[2] + U[5] * X[5] + U[8] * X[8]);
    R[8] = V[2] * (U[2] * X[0] + U[5] * X[3] + U[8] * X[6]) + V[5] * (U[2] * X[1] + U[5] * X[4] + U[8] * X[7]) + V[8] * (U[2] * X[2] + U[5] * X[5] + U[8] * X[8]);
}

template <class T>
__host__ __device__ __forceinline__ void matUDVT3(T* R, const T* U, const T* D, const T* V)
{
    R[0] = D[0] * U[0] * V[0] + D[1] * U[1] * V[1] + D[2] * U[2] * V[2];
    R[1] = D[0] * U[0] * V[3] + D[1] * U[1] * V[4] + D[2] * U[2] * V[5];
    R[2] = D[0] * U[0] * V[6] + D[1] * U[1] * V[7] + D[2] * U[2] * V[8];
    R[3] = D[0] * U[3] * V[0] + D[1] * U[4] * V[1] + D[2] * U[5] * V[2];
    R[4] = D[0] * U[3] * V[3] + D[1] * U[4] * V[4] + D[2] * U[5] * V[5];
    R[5] = D[0] * U[3] * V[6] + D[1] * U[4] * V[7] + D[2] * U[5] * V[8];
    R[6] = D[0] * U[6] * V[0] + D[1] * U[7] * V[1] + D[2] * U[8] * V[2];
    R[7] = D[0] * U[6] * V[3] + D[1] * U[7] * V[4] + D[2] * U[8] * V[5];
    R[8] = D[0] * U[6] * V[6] + D[1] * U[7] * V[7] + D[2] * U[8] * V[8];
}

template <class T>
__host__ __device__ __forceinline__ void matUTDV3(T* R, const T* U, const T* D, const T* V)
{
    R[0] = D[0] * U[0] * V[0] + D[1] * U[3] * V[3] + D[2] * U[6] * V[6];
    R[1] = D[0] * U[0] * V[1] + D[1] * U[3] * V[4] + D[2] * U[6] * V[7];
    R[2] = D[0] * U[0] * V[2] + D[1] * U[3] * V[5] + D[2] * U[6] * V[8];
    R[3] = D[0] * U[1] * V[0] + D[1] * U[4] * V[3] + D[2] * U[7] * V[6];
    R[4] = D[0] * U[1] * V[1] + D[1] * U[4] * V[4] + D[2] * U[7] * V[7];
    R[5] = D[0] * U[1] * V[2] + D[1] * U[4] * V[5] + D[2] * U[7] * V[8];
    R[6] = D[0] * U[2] * V[0] + D[1] * U[5] * V[3] + D[2] * U[8] * V[6];
    R[7] = D[0] * U[2] * V[1] + D[1] * U[5] * V[4] + D[2] * U[8] * V[7];
    R[8] = D[0] * U[2] * V[2] + D[1] * U[5] * V[5] + D[2] * U[8] * V[8];
}

template <class T>
__host__ __device__ __forceinline__ void matUDVT2(T* R, const T* U, const T* D, const T* V)
{
    R[0] = D[0] * U[0] * V[0] + D[1] * U[1] * V[1];
    R[1] = D[0] * U[0] * V[2] + D[1] * U[1] * V[3];
    R[2] = D[0] * U[2] * V[0] + D[1] * U[3] * V[1];
    R[3] = D[0] * U[2] * V[2] + D[1] * U[3] * V[3];
}

template <class T>
__host__ __device__ __forceinline__ void matUTDV2(T* R, const T* U, const T* D, const T* V)
{
    R[0] = D[0] * U[0] * V[0] + D[1] * U[2] * V[2];
    R[1] = D[0] * U[0] * V[1] + D[1] * U[2] * V[3];
    R[2] = D[0] * U[1] * V[0] + D[1] * U[3] * V[2];
    R[3] = D[0] * U[1] * V[1] + D[1] * U[3] * V[3];
}

template <class T>
__host__ __device__ __forceinline__ void matTrans3(T* X_trans, const T* X)
{
    X_trans[0] = X[0];
    X_trans[3] = X[1];
    X_trans[6] = X[2];
    X_trans[1] = X[3];
    X_trans[4] = X[4];
    X_trans[7] = X[5];
    X_trans[2] = X[6];
    X_trans[5] = X[7];
    X_trans[8] = X[8];
}

template <class T>
__host__ __device__ __forceinline__ void matTrans(T* X_trans, const T* X, unsigned int rows, unsigned int cols)
{
    for (unsigned int i = 0; i < rows; ++i)
    {
        for (unsigned int j = 0; j < cols; ++j)
        {
            X_trans[j * rows + i] = X[i * cols + j];
        }
    }
}

template <typename UInt>
__device__ inline int common_upper_bits(const UInt x, const UInt y)
{
    if (sizeof(UInt) == sizeof(unsigned int))
        return __clz(x ^ y);
    else
        return __clzll(x ^ y);
}

template <class T>
__host__ __device__ __forceinline__ void matVecMul(T* X, const T* A, const T* b, const int rows, const int cols)
{
    // memset(X, 0, sizeof(T) * rows * cols);
    for (int i = 0; i < rows; ++i)
        X[i] = 0.0;
    for (int i = 0; i < rows; ++i)
        for (int j = 0; j < cols; ++j)
            X[i] += A[i * cols + j] * b[j];
}

template <class T>
__host__ __device__ __forceinline__ void matTVecMul(T* X, const T* A, const T* b, const int rows, const int cols) // transposed rows and cols
{
    // memset(X, 0, sizeof(T) * rows * cols);
    for (int i = 0; i < rows; ++i)
        X[i] = 0.0;
    for (int i = 0; i < rows; ++i)
        for (int j = 0; j < cols; ++j)
            X[i] += A[i + j * rows] * b[j];
}

template <class T>
__host__ __device__ __forceinline__ void matMul(T* X, const T* A, const T* B, const int rows, const int inner, int cols)
{
    // memset(X, 0, sizeof(T) * rows * cols);
    for (int i = 0; i < rows * cols; ++i)
        X[i] = 0.0;
    for (int i = 0; i < rows; ++i)
        for (int j = 0; j < cols; ++j)
            for (int k = 0; k < inner; ++k)
                X[i * cols + j] += A[i * inner + k] * B[k * cols + j];
}

template <class T>
__host__ __device__ __forceinline__ void matTMul(T* X, const T* A, const T* B, const int rows, const int inner, const int cols) // transposed rows, inner and cols
{
    // memset(X, 0, sizeof(T) * rows * cols);
    for (int i = 0; i < rows * cols; ++i)
        X[i] = 0.0;
    for (int i = 0; i < rows; ++i)
        for (int j = 0; j < cols; ++j)
            for (int k = 0; k < inner; ++k)
                X[i * cols + j] += A[k * rows + i] * B[k * cols + j];
}

template <class T>
__host__ __device__ __forceinline__ void matMulT(T* X, const T* A, const T* B, const int rows, const int inner, const int cols)
{
    // memset(X, 0, sizeof(T) * rows * cols);
    for (int i = 0; i < rows * cols; ++i)
        X[i] = 0.0;
    for (int i = 0; i < rows; ++i)
        for (int j = 0; j < cols; ++j)
            for (int k = 0; k < inner; ++k)
                X[i * cols + j] += A[i * inner + k] * B[j * inner + k];
}

template <typename Real>
__host__ __device__ __forceinline__ void aUXVT3(Real* result, const Real a, const Real* U, const Real* X, const Real* V)
{
    result[0] = V[0] * (X[0] * U[0] * a + X[3] * U[1] * a + X[6] * U[2] * a) + V[1] * (X[1] * U[0] * a + X[4] * U[1] * a + X[7] * U[2] * a) + V[2] * (X[2] * U[0] * a + X[5] * U[1] * a + X[8] * U[2] * a);
    result[1] = V[3] * (X[0] * U[0] * a + X[3] * U[1] * a + X[6] * U[2] * a) + V[4] * (X[1] * U[0] * a + X[4] * U[1] * a + X[7] * U[2] * a) + V[5] * (X[2] * U[0] * a + X[5] * U[1] * a + X[8] * U[2] * a);
    result[2] = V[6] * (X[0] * U[0] * a + X[3] * U[1] * a + X[6] * U[2] * a) + V[7] * (X[1] * U[0] * a + X[4] * U[1] * a + X[7] * U[2] * a) + V[8] * (X[2] * U[0] * a + X[5] * U[1] * a + X[8] * U[2] * a);
    result[3] = V[0] * (X[0] * U[3] * a + X[3] * U[4] * a + X[6] * U[5] * a) + V[1] * (X[1] * U[3] * a + X[4] * U[4] * a + X[7] * U[5] * a) + V[2] * (X[2] * U[3] * a + X[5] * U[4] * a + X[8] * U[5] * a);
    result[4] = V[3] * (X[0] * U[3] * a + X[3] * U[4] * a + X[6] * U[5] * a) + V[4] * (X[1] * U[3] * a + X[4] * U[4] * a + X[7] * U[5] * a) + V[5] * (X[2] * U[3] * a + X[5] * U[4] * a + X[8] * U[5] * a);
    result[5] = V[6] * (X[0] * U[3] * a + X[3] * U[4] * a + X[6] * U[5] * a) + V[7] * (X[1] * U[3] * a + X[4] * U[4] * a + X[7] * U[5] * a) + V[8] * (X[2] * U[3] * a + X[5] * U[4] * a + X[8] * U[5] * a);
    result[6] = V[0] * (X[0] * U[6] * a + X[3] * U[7] * a + X[6] * U[8] * a) + V[1] * (X[1] * U[6] * a + X[4] * U[7] * a + X[7] * U[8] * a) + V[2] * (X[2] * U[6] * a + X[5] * U[7] * a + X[8] * U[8] * a);
    result[7] = V[3] * (X[0] * U[6] * a + X[3] * U[7] * a + X[6] * U[8] * a) + V[4] * (X[1] * U[6] * a + X[4] * U[7] * a + X[7] * U[8] * a) + V[5] * (X[2] * U[6] * a + X[5] * U[7] * a + X[8] * U[8] * a);
    result[8] = V[6] * (X[0] * U[6] * a + X[3] * U[7] * a + X[6] * U[8] * a) + V[7] * (X[1] * U[6] * a + X[4] * U[7] * a + X[7] * U[8] * a) + V[8] * (X[2] * U[6] * a + X[5] * U[7] * a + X[8] * U[8] * a);
}

template <class T>
__host__ __device__ __forceinline__ void dyadicN(T* X, T* a, T* b, unsigned int N)
{
    for (int i = 0; i < N; ++i)
        for (int j = 0; j < N; ++j)
            X[N * i + j] = a[i] * b[j];
}

template <class T>
__host__ __device__ __forceinline__ void accumulate(T* X, T a, T* B, unsigned int N)
{
    for (int i = 0; i < N; ++i)
        X[i] += a * B[i];
}

template <class T>
__host__ __device__ __forceinline__ void accumulate(T* X, T* A, T* B, unsigned int N)
{
    for (int i = 0; i < N; ++i)
        X[i] += A[i] * B[i];
}

template <class T>
__host__ __device__ __forceinline__ void safeMatInv3(T* inv_X, T* X)
{
    // check if the determinant is nonzero
    T detX;
    det3<T>(detX, X);
    if (abs<T>(detX) > EPSILON)
    {
        matInv3<T>(inv_X, X);
        return;
    }
    printf(">>>>> math_cuda.h [safeMatInv3] singular matrix inversion!");
    // for (int i = 0; i < 9; ++i) printf("%f ", X[i]); printf("\n");
    for (int i = 0; i < 3; ++i)
        for (int j = 0; j < 3; ++j)
        {
            if (i == j)
                inv_X[3 * i + j] = 1.0;
            else
                inv_X[3 * i + j] = 0.0;
        }
}

template <class T>
__host__ __device__ __forceinline__ void setZero(T* v, unsigned int n)
{
    for (int i = 0; i < n; ++i)
        v[i] = 0.0;
}

template <class T>
__host__ __device__ __forceinline__ void axpby(T* v, unsigned int n, T a, T* x, T b, T* y)
{
    for (int i = 0; i < n; ++i)
    {
        v[i] = a * x[i] + b * y[i];
    }
}

template <class T>
__host__ __device__ __forceinline__ void axpbypcz(T* v, unsigned int n, T a, T* x, T b, T* y, T c, T* z)
{
    for (int i = 0; i < n; ++i)
    {
        v[i] = a * x[i] + b * y[i] + c * z[i];
    }
}

// the scalar triple product
template <class T>
__host__ __device__ __forceinline__
T
stp3(T* u, T* v, T* w)
{
    // u \dot v \cross w
    return u[2] * (v[0] * w[1] - v[1] * w[0]) - u[1] * (v[0] * w[2] - v[2] * w[0]) + u[0] * (v[1] * w[2] - v[2] * w[1]);
}

template <class T>
__host__ __device__ __forceinline__ void lerp3(T* x, T* x0, T* x1, T t)
{
    for (unsigned int i = 0; i < 3; ++i)
    {
        x[i] = x0[i] + t * (x1[i] - x0[i]);
    }
}

template <typename Real>
__global__ void axpby_kernel(unsigned int n, Real* r, Real a, Real* x, Real b, Real* y)
{
    unsigned int i = blockDim.x * blockIdx.x + threadIdx.x;
    if (i >= n) return;
    r[i] = a * x[i] + b * y[i];
}

template <typename Real>
__global__ void axpbypcz_kernel(unsigned int n, Real* r, Real a, Real* x, Real b, Real* y, Real c, Real* z)
{
    unsigned int i = blockDim.x * blockIdx.x + threadIdx.x;
    if (i >= n)
        return;
    r[i] = a * x[i] + b * y[i] + c * z[i];
}

template <typename Real>
__global__ void negate_kernel(unsigned int n, Real* r, Real* x)
{
    unsigned int i = blockDim.x * blockIdx.x + threadIdx.x;
    if (i >= n)
        return;
    r[i] = -x[i];
}

template <typename Real>
__host__ __device__ void get_rotation(Real* R, const Real* F)
{
    Real C[9];
    memset(C, 0, sizeof(Real) * 9);
    for (int i = 0; i < 3; i++)
        for (int j = 0; j < 3; j++)
            for (int k = 0; k < 3; k++)
                C[3 * i + j] += F[3 * k + i] * F[3 * k + j];

    Real C2[9];
    memset(C2, 0, sizeof(Real) * 9);
    for (int i = 0; i < 3; i++)
        for (int j = 0; j < 3; j++)
            for (int k = 0; k < 3; k++)
                C2[3 * i + j] += C[3 * i + k] * C[3 * j + k];

    Real det = F[0] * F[4] * F[8] +
        F[1] * F[5] * F[6] +
        F[3] * F[7] * F[2] -
        F[2] * F[4] * F[6] -
        F[1] * F[3] * F[8] -
        F[0] * F[5] * F[7];

    Real I_c = C[0] + C[4] + C[8];
    Real I_c2 = I_c * I_c;
    Real II_c = 0.5 * (I_c2 - C2[0] - C2[4] - C2[8]);
    Real III_c = det * det;
    Real k = I_c2 - 3 * II_c;

    Real inv_U[9];
    if (k < EPSILON)
    {
        Real inv_lambda = 1 / sqrt(I_c / 3);
        memset(inv_U, 0, sizeof(Real) * 9);
        inv_U[0] = inv_lambda;
        inv_U[4] = inv_lambda;
        inv_U[8] = inv_lambda;
    }
    else
    {
        Real l = I_c * (I_c * I_c - 4.5 * II_c) + 13.5 * III_c;
        Real k_root = sqrt(k);
        Real value = l / (k * k_root);
        if (value < -1.0)
            value = -1.0;
        if (value > 1.0)
            value = 1.0;
        Real phi = acos(value);
        Real lambda2 = (I_c + 2 * k_root * cos(phi / 3)) / 3.0;
        Real lambda = sqrt(lambda2);

        Real III_u = sqrt(III_c);
        if (det < 0)
            III_u = -III_u;
        Real I_u = lambda + sqrt(-lambda2 + I_c + 2 * III_u / lambda);
        Real II_u = (I_u * I_u - I_c) * 0.5;

        Real U[9];
        Real inv_rate, factor;

        inv_rate = 1 / (I_u * II_u - III_u);
        factor = I_u * III_u * inv_rate;

        memset(U, 0, sizeof(Real) * 9);
        U[0] = factor;
        U[4] = factor;
        U[8] = factor;

        factor = (I_u * I_u - II_u) * inv_rate;
        for (int i = 0; i < 3; i++)
            for (int j = 0; j < 3; j++)
                U[3 * i + j] += factor * C[3 * i + j] - inv_rate * C2[3 * i + j];

        inv_rate = 1 / III_u;
        factor = II_u * inv_rate;
        memset(inv_U, 0, sizeof(Real) * 9);
        inv_U[0] = factor;
        inv_U[4] = factor;
        inv_U[8] = factor;

        factor = -I_u * inv_rate;
        for (int i = 0; i < 3; i++)
            for (int j = 0; j < 3; j++)
                inv_U[3 * i + j] += factor * U[3 * i + j] + inv_rate * C[3 * i + j];
    }

    memset(R, 0, sizeof(Real) * 9);
    for (int i = 0; i < 3; i++)
        for (int j = 0; j < 3; j++)
            for (int k = 0; k < 3; k++)
                R[3 * i + j] += F[3 * i + k] * inv_U[3 * k + j];
}

template <typename Real>
inline Real inner_product(unsigned int N, Real* a, Real* b)
{
    if (N == 0) return 0.;
    //Real* result; result = new Real(0);
    //Real* d_result; cudaMalloc(&d_result, sizeof(Real));
    //cudaMemcpy(d_result, result, sizeof(Real), cudaMemcpyHostToDevice);
    //inner_product_kernel<Real> << <get_blocksPerGrid(N), THREADS_PER_BLOCK >> > (N, a, b, d_result);
    //cudaMemcpy(result, d_result, sizeof(Real), cudaMemcpyDeviceToHost);
    ////std::cout << "inner product = " << *result << std::endl;
    //Real r = *result;
    //cudaFree(d_result);
    //delete[] result;
    //return r;
    return thrust::inner_product(thrust::device, a, a + N, b, 0.);
}

template <typename Real>
__host__ __device__ __forceinline__ Real dot(unsigned int N, Real* a, Real* b)
{
    Real r = 0.;
    for (unsigned int i = 0; i < N; ++i)
    {
        r += a[i] * b[i];
    }
    return r;
}

template <class T>
__host__ __device__ __forceinline__ void set_zero(T* x, unsigned int N)
{
    memset(x, 0, sizeof(T) * N);
}

template <class T>
__host__ __device__ __forceinline__ T normSquared(const T* x, unsigned int N)
{
    T n = 0.;
    for (unsigned int i = 0; i < N; ++i)
    {
        n += x[i] * x[i];
    }
    return n;
}

template<typename Real>
__host__ __device__ __forceinline__ Real radians(Real degrees)
{
    return degrees * PI / 180.;
}

template<typename Real>
__host__ __device__ __forceinline__ Real degrees(Real radians)
{
    return radians / PI * 180.;
}

template<typename Real>
__global__ void vecMul_kernel(unsigned int n, Real coeff, Real* array)
{
    unsigned int i = blockDim.x * blockIdx.x + threadIdx.x;
    if (i >= n) return;
    array[i] *= coeff;
}

template<typename Real>
__global__ void vecMul_kernel(unsigned int n, Real coeff, Real* array_in, Real* array_out)
{
    unsigned int i = blockDim.x * blockIdx.x + threadIdx.x;
    if (i >= n) return;
    array_out[i] = coeff * array_in[i];
}

template<typename Real>
__host__ __device__ __forceinline__ Real average(Real* data, unsigned int n)
{
    Real sum = 0.;
    for (unsigned int i = 0; i < n; ++i)
    {
        sum += data[i];
    }
    return Real(1. / n) * sum;
}

template<typename Real>
__host__ __device__ __forceinline__ void affine_transform(Real* DOF, Real* rest_x, Real* x)
{
    x[0] = DOF[0] * rest_x[0] + DOF[1] * rest_x[1] + DOF[2] * rest_x[2] + DOF[9];
    x[1] = DOF[3] * rest_x[0] + DOF[4] * rest_x[1] + DOF[5] * rest_x[2] + DOF[10];
    x[2] = DOF[6] * rest_x[0] + DOF[7] * rest_x[1] + DOF[8] * rest_x[2] + DOF[11];
}

template<typename Real>
__host__ __device__ __forceinline__ void SE3_mul(Real* DOF0, Real* DOF1, Real* DOF)
{
    DOF[0] = DOF0[0] * DOF1[0] + DOF0[3] * DOF1[1] + DOF0[6] * DOF1[2];
    DOF[1] = DOF0[1] * DOF1[0] + DOF0[4] * DOF1[1] + DOF0[7] * DOF1[2];
    DOF[2] = DOF0[2] * DOF1[0] + DOF0[5] * DOF1[1] + DOF0[8] * DOF1[2];
    DOF[3] = DOF0[0] * DOF1[3] + DOF0[3] * DOF1[4] + DOF0[6] * DOF1[5];
    DOF[4] = DOF0[1] * DOF1[3] + DOF0[4] * DOF1[4] + DOF0[7] * DOF1[5];
    DOF[5] = DOF0[2] * DOF1[3] + DOF0[5] * DOF1[4] + DOF0[8] * DOF1[5];
    DOF[6] = DOF0[0] * DOF1[6] + DOF0[3] * DOF1[7] + DOF0[6] * DOF1[8];
    DOF[7] = DOF0[1] * DOF1[6] + DOF0[4] * DOF1[7] + DOF0[7] * DOF1[8];
    DOF[8] = DOF0[2] * DOF1[6] + DOF0[5] * DOF1[7] + DOF0[8] * DOF1[8];
    DOF[9]  = DOF1[9] + DOF0[9] * DOF1[0] + DOF0[10] * DOF1[1] + DOF0[11] * DOF1[2];
    DOF[10] = DOF1[10] + DOF0[9] * DOF1[3] + DOF0[10] * DOF1[4] + DOF0[11] * DOF1[5];
    DOF[11] = DOF1[11] + DOF0[9] * DOF1[6] + DOF0[10] * DOF1[7] + DOF0[11] * DOF1[8];
}

template<typename t1, typename t2>
__host__ __device__ __forceinline__ void type_casting(t1* in, t2* out, unsigned int N)
{
    for (unsigned int i = 0; i < N; ++i)
    {
        out[i] = (t2)in[i];
    }
}

template <typename Real>
__global__ void mass_vec_kernel(unsigned int nVerts, Real* masses, Real* vec, Real* result)
{
    unsigned int v = blockDim.x * blockIdx.x + threadIdx.x;
    if (v >= nVerts) return;
    result[3 * v] = masses[v] * vec[3 * v];
    result[3 * v + 1] = masses[v] * vec[3 * v + 1];
    result[3 * v + 2] = masses[v] * vec[3 * v + 2];
}

template <typename Real>
__global__ void mat_vec_product_kernel(unsigned int m, unsigned int n, Real* A, Real* x, Real* y)
{
    unsigned int i = blockDim.x * blockIdx.x + threadIdx.x;
    if (i < m)
    {
        Real sum = 0;
        for (unsigned int j = 0; j < n; ++j)
        {
            sum += A[i * n + j] * x[j];
        }
        y[i] = sum;
    }

}

template <typename Real>
__global__ void matTvec_product_kernel(unsigned int m, unsigned int n, Real* A, Real* x, Real* y)
{
    unsigned int j = blockDim.x * blockIdx.x + threadIdx.x;
    if (j < n)
    {
        Real sum = 0;
        for (unsigned int i = 0; i < m; ++i) {
            sum += A[i * n + j] * x[i];
        }
        y[j] = sum;
    }
}

template <typename Real>
void compute_matVec_product_cuda(Real* A, Real* x, Real* y, unsigned int m, unsigned int n)
{
    mat_vec_product_kernel<Real><<<get_blocksPerGrid(m), THREADS_PER_BLOCK>>>(m, n, A, x, y);
}

template <typename Real>
void compute_matTVec_product_cuda(Real* A, Real* x, Real* y, unsigned int m, unsigned int n)
{
    matTvec_product_kernel<Real><<<get_blocksPerGrid(n), THREADS_PER_BLOCK>>>(m, n, A, x, y);
}