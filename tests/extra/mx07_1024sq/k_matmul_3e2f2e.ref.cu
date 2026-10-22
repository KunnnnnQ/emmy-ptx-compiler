static __device__ __forceinline__ void emmy_cp_async_cg(void* smem, const void* gmem) {
    unsigned addr = __cvta_generic_to_shared(smem);
    asm volatile("cp.async.cg.shared.global [%0], [%1], 16;\n" :: "r"(addr), "l"(gmem) : "memory");
}

template <int Bytes>
static __device__ __forceinline__ void emmy_cp_async_ca(void* smem, const void* gmem) {
    unsigned addr = __cvta_generic_to_shared(smem);
    asm volatile("cp.async.ca.shared.global [%0], [%1], %2;\n" :: "r"(addr), "l"(gmem), "n"(Bytes) : "memory");
}

static __device__ __forceinline__ void emmy_cp_async_commit() {
    asm volatile("cp.async.commit_group;\n" ::: "memory");
}

template <int N>
static __device__ __forceinline__ void emmy_cp_async_wait() {
    asm volatile("cp.async.wait_group %0;\n" :: "n"(N) : "memory");
}

extern "C" __global__
__launch_bounds__(512) void k_matmul_3e2f2e(const float* x1, const float* x0, float* matmul) {
    extern __shared__ __align__(16) unsigned char _smem_pool[];  // 57344 bytes
    int _gid = blockIdx.x * blockDim.x + threadIdx.x;
        int a0_b = _gid / 4096;
        int a1_b = (_gid / 512) % 8;
        int a0_u = (_gid / 64) % 8;
        int a1_u = (_gid) % 64;
        float acc0__c0_0 = 0.0f;
        float acc0__c0_1 = 0.0f;
        float acc0__c1_0 = 0.0f;
        float acc0__c1_1 = 0.0f;
        float acc0__c2_0 = 0.0f;
        float acc0__c2_1 = 0.0f;
        float acc0__c3_0 = 0.0f;
        float acc0__c3_1 = 0.0f;
        float acc0__c4_0 = 0.0f;
        float acc0__c4_1 = 0.0f;
        float acc0__c5_0 = 0.0f;
        float acc0__c5_1 = 0.0f;
        float acc0__c6_0 = 0.0f;
        float acc0__c6_1 = 0.0f;
        float acc0__c7_0 = 0.0f;
        float acc0__c7_1 = 0.0f;
        float acc0__c8_0 = 0.0f;
        float acc0__c8_1 = 0.0f;
        float acc0__c9_0 = 0.0f;
        float acc0__c9_1 = 0.0f;
        float acc0__c10_0 = 0.0f;
        float acc0__c10_1 = 0.0f;
        float acc0__c11_0 = 0.0f;
        float acc0__c11_1 = 0.0f;
        float* _a_smem = reinterpret_cast<float*>(_smem_pool + 0);
        float* _b_smem = reinterpret_cast<float*>(_smem_pool + 24576);
        for (int _fa = a0_u * 64 + a1_u; _fa < 768; _fa += 512) {
            emmy_cp_async_cg(&_a_smem[_fa * 4], &x0[((a0_b * 96 + _fa / 8 < 1024) ? (a0_b * 96 + _fa / 8) : (1023)) * 1024 + 4 * (_fa % 8)]);
        }
        emmy_cp_async_cg(&_b_smem[0 + ((a0_u * 64 + a1_u) * 4 / 128) * 128 + ((a0_u * 64 + a1_u) * 4 % 128)], &x1[(a0_u * 64 + a1_u) / 32 * 1024 + (a1_b * 128 + 4 * ((a0_u * 64 + a1_u) % 32))]);
        emmy_cp_async_cg(&_b_smem[2048 + ((a0_u * 64 + a1_u) * 4 / 128) * 128 + ((a0_u * 64 + a1_u) * 4 % 128)], &x1[((a0_u * 64 + a1_u) / 32 + 16) * 1024 + (a1_b * 128 + 4 * ((a0_u * 64 + a1_u) % 32))]);
        emmy_cp_async_commit();
        for (int _ks = 0; _ks < 1024; _ks += 32) {
            for (int _fa = a0_u * 64 + a1_u; _fa < 768; _fa += 512) {
                emmy_cp_async_cg(&_a_smem[((_ks / 32 + 1) % 2 * 96 + _fa / 8) * 32 + 4 * (_fa % 8)], &x0[((a0_b * 96 + _fa / 8 < 1024) ? (a0_b * 96 + _fa / 8) : (1023)) * 1024 + (((_ks + 32 < 1024) ? (_ks + 32) : (992)) + 4 * (_fa % 8))]);
            }
            emmy_cp_async_cg(&_b_smem[(_ks / 32 + 1) % 2 * 32 * 128 + ((a0_u * 64 + a1_u) * 4 / 128) * 128 + ((a0_u * 64 + a1_u) * 4 % 128)], &x1[(((_ks + 32 < 1024) ? (_ks + 32) : (992)) + (a0_u * 64 + a1_u) / 32) * 1024 + (a1_b * 128 + 4 * ((a0_u * 64 + a1_u) % 32))]);
            emmy_cp_async_cg(&_b_smem[((_ks / 32 + 1) % 2 * 32 + 16) * 128 + ((a0_u * 64 + a1_u) * 4 / 128) * 128 + ((a0_u * 64 + a1_u) * 4 % 128)], &x1[(((_ks + 32 < 1024) ? (_ks + 32) : (992)) + ((a0_u * 64 + a1_u) / 32 + 16)) * 1024 + (a1_b * 128 + 4 * ((a0_u * 64 + a1_u) % 32))]);
            emmy_cp_async_commit();
            emmy_cp_async_wait<1>();
            __syncthreads();
            #pragma unroll
            for (int _ki = 0; _ki < 32; _ki++) {
                float in1__c0_0 = _b_smem[(_ks / 32 % 2 * 32 + _ki) * 128 + (a1_b * 128 + a1_u * 2 - a1_b * 128)];
                float in0__c0_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c0_0 = in1__c0_0 * in0__c0_0;
                acc0__c0_0 += acc0__v__c0_0;
                float in1__c0_1 = _b_smem[(_ks / 32 % 2 * 32 + _ki) * 128 + (a1_b * 128 + a1_u * 2 + 1 - a1_b * 128)];
                float acc0__v__c0_1 = in1__c0_1 * in0__c0_0;
                acc0__c0_1 += acc0__v__c0_1;
                float in0__c1_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 1 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c1_0 = in1__c0_0 * in0__c1_0;
                acc0__c1_0 += acc0__v__c1_0;
                float acc0__v__c1_1 = in1__c0_1 * in0__c1_0;
                acc0__c1_1 += acc0__v__c1_1;
                float in0__c2_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 2 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c2_0 = in1__c0_0 * in0__c2_0;
                acc0__c2_0 += acc0__v__c2_0;
                float acc0__v__c2_1 = in1__c0_1 * in0__c2_0;
                acc0__c2_1 += acc0__v__c2_1;
                float in0__c3_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 3 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c3_0 = in1__c0_0 * in0__c3_0;
                acc0__c3_0 += acc0__v__c3_0;
                float acc0__v__c3_1 = in1__c0_1 * in0__c3_0;
                acc0__c3_1 += acc0__v__c3_1;
                float in0__c4_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 4 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c4_0 = in1__c0_0 * in0__c4_0;
                acc0__c4_0 += acc0__v__c4_0;
                float acc0__v__c4_1 = in1__c0_1 * in0__c4_0;
                acc0__c4_1 += acc0__v__c4_1;
                float in0__c5_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 5 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c5_0 = in1__c0_0 * in0__c5_0;
                acc0__c5_0 += acc0__v__c5_0;
                float acc0__v__c5_1 = in1__c0_1 * in0__c5_0;
                acc0__c5_1 += acc0__v__c5_1;
                float in0__c6_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 6 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c6_0 = in1__c0_0 * in0__c6_0;
                acc0__c6_0 += acc0__v__c6_0;
                float acc0__v__c6_1 = in1__c0_1 * in0__c6_0;
                acc0__c6_1 += acc0__v__c6_1;
                float in0__c7_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 7 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c7_0 = in1__c0_0 * in0__c7_0;
                acc0__c7_0 += acc0__v__c7_0;
                float acc0__v__c7_1 = in1__c0_1 * in0__c7_0;
                acc0__c7_1 += acc0__v__c7_1;
                float in0__c8_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 8 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c8_0 = in1__c0_0 * in0__c8_0;
                acc0__c8_0 += acc0__v__c8_0;
                float acc0__v__c8_1 = in1__c0_1 * in0__c8_0;
                acc0__c8_1 += acc0__v__c8_1;
                float in0__c9_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 9 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c9_0 = in1__c0_0 * in0__c9_0;
                acc0__c9_0 += acc0__v__c9_0;
                float acc0__v__c9_1 = in1__c0_1 * in0__c9_0;
                acc0__c9_1 += acc0__v__c9_1;
                float in0__c10_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 10 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c10_0 = in1__c0_0 * in0__c10_0;
                acc0__c10_0 += acc0__v__c10_0;
                float acc0__v__c10_1 = in1__c0_1 * in0__c10_0;
                acc0__c10_1 += acc0__v__c10_1;
                float in0__c11_0 = _a_smem[(_ks / 32 % 2 * 96 + (a0_b * 96 + a0_u * 12 + 11 - a0_b * 96)) * 32 + _ki];
                float acc0__v__c11_0 = in1__c0_0 * in0__c11_0;
                acc0__c11_0 += acc0__v__c11_0;
                float acc0__v__c11_1 = in1__c0_1 * in0__c11_0;
                acc0__c11_1 += acc0__v__c11_1;
            }
            __syncthreads();
        }
        if (a0_b * 96 + a0_u * 12 + 0 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c0_0;
        }
        if (a0_b * 96 + a0_u * 12 + 0 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c0_1;
        }
        if (a0_b * 96 + a0_u * 12 + 1 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 1) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c1_0;
        }
        if (a0_b * 96 + a0_u * 12 + 1 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 1) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c1_1;
        }
        if (a0_b * 96 + a0_u * 12 + 2 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 2) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c2_0;
        }
        if (a0_b * 96 + a0_u * 12 + 2 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 2) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c2_1;
        }
        if (a0_b * 96 + a0_u * 12 + 3 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 3) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c3_0;
        }
        if (a0_b * 96 + a0_u * 12 + 3 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 3) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c3_1;
        }
        if (a0_b * 96 + a0_u * 12 + 4 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 4) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c4_0;
        }
        if (a0_b * 96 + a0_u * 12 + 4 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 4) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c4_1;
        }
        if (a0_b * 96 + a0_u * 12 + 5 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 5) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c5_0;
        }
        if (a0_b * 96 + a0_u * 12 + 5 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 5) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c5_1;
        }
        if (a0_b * 96 + a0_u * 12 + 6 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 6) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c6_0;
        }
        if (a0_b * 96 + a0_u * 12 + 6 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 6) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c6_1;
        }
        if (a0_b * 96 + a0_u * 12 + 7 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 7) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c7_0;
        }
        if (a0_b * 96 + a0_u * 12 + 7 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 7) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c7_1;
        }
        if (a0_b * 96 + a0_u * 12 + 8 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 8) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c8_0;
        }
        if (a0_b * 96 + a0_u * 12 + 8 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 8) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c8_1;
        }
        if (a0_b * 96 + a0_u * 12 + 9 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 9) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c9_0;
        }
        if (a0_b * 96 + a0_u * 12 + 9 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 9) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c9_1;
        }
        if (a0_b * 96 + a0_u * 12 + 10 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 10) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c10_0;
        }
        if (a0_b * 96 + a0_u * 12 + 10 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 10) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c10_1;
        }
        if (a0_b * 96 + a0_u * 12 + 11 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 11) % 1024 * 1024 + (a1_b * 128 + a1_u * 2)] = acc0__c11_0;
        }
        if (a0_b * 96 + a0_u * 12 + 11 < 1024) {
            matmul[(a0_b * 96 + a0_u * 12 + 11) % 1024 * 1024 + (a1_b * 128 + a1_u * 2 + 1)] = acc0__c11_1;
        }
}
