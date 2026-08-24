/*
 * SHA256 implementation for CUDA
 */

#ifndef SHA256_CUH
#define SHA256_CUH

#include <stdint.h>

__constant__ uint32_t K256[64] = {
    0x428a2f98, 0x71374491, 0xb5c0fbcf, 0xe9b5dba5, 0x3956c25b, 0x59f111f1, 0x923f82a4, 0xab1c5ed5,
    0xd807aa98, 0x12835b01, 0x243185be, 0x550c7dc3, 0x72be5d74, 0x80deb1fe, 0x9bdc06a7, 0xc19bf174,
    0xe49b69c1, 0xefbe4786, 0x0fc19dc6, 0x240ca1cc, 0x2de92c6f, 0x4a7484aa, 0x5cb0a9dc, 0x76f988da,
    0x983e5152, 0xa831c66d, 0xb00327c8, 0xbf597fc7, 0xc6e00bf3, 0xd5a79147, 0x06ca6351, 0x14292967,
    0x27b70a85, 0x2e1b2138, 0x4d2c6dfc, 0x53380d13, 0x650a7354, 0x766a0abb, 0x81c2c92e, 0x92722c85,
    0xa2bfe8a1, 0xa81a664b, 0xc24b8b70, 0xc76c51a3, 0xd192e819, 0xd6990624, 0xf40e3585, 0x106aa070,
    0x19a4c116, 0x1e376c08, 0x2748774c, 0x34b0bcb5, 0x391c0cb3, 0x4ed8aa4a, 0x5b9cca4f, 0x682e6ff3,
    0x748f82ee, 0x78a5636f, 0x84c87814, 0x8cc70208, 0x90befffa, 0xa4506ceb, 0xbef9a3f7, 0xc67178f2
};

__device__ __forceinline__ uint32_t rotr32(uint32_t x, uint32_t n) {
    return (x >> n) | (x << (32 - n));
}

__device__ __forceinline__ uint32_t ch(uint32_t x, uint32_t y, uint32_t z) {
    return (x & y) ^ (~x & z);
}

__device__ __forceinline__ uint32_t maj(uint32_t x, uint32_t y, uint32_t z) {
    return (x & y) ^ (x & z) ^ (y & z);
}

__device__ __forceinline__ uint32_t sigma0_256(uint32_t x) {
    return rotr32(x, 2) ^ rotr32(x, 13) ^ rotr32(x, 22);
}

__device__ __forceinline__ uint32_t sigma1_256(uint32_t x) {
    return rotr32(x, 6) ^ rotr32(x, 11) ^ rotr32(x, 25);
}

__device__ __forceinline__ uint32_t gamma0_256(uint32_t x) {
    return rotr32(x, 7) ^ rotr32(x, 18) ^ (x >> 3);
}

__device__ __forceinline__ uint32_t gamma1_256(uint32_t x) {
    return rotr32(x, 17) ^ rotr32(x, 19) ^ (x >> 10);
}

__device__ void sha256_transform(uint32_t* state, const uint8_t* block) {
    uint32_t W[64];
    uint32_t a, b, c, d, e, f, g, h;
    uint32_t t1, t2;
    
    // Preparar message schedule - unrolled
    #pragma unroll 16
    for (int i = 0; i < 16; i++) {
        W[i] = ((uint32_t)block[i * 4] << 24) |
               ((uint32_t)block[i * 4 + 1] << 16) |
               ((uint32_t)block[i * 4 + 2] << 8) |
               ((uint32_t)block[i * 4 + 3]);
    }
    
    #pragma unroll 48
    for (int i = 16; i < 64; i++) {
        W[i] = gamma1_256(W[i - 2]) + W[i - 7] + gamma0_256(W[i - 15]) + W[i - 16];
    }
    
    a = state[0]; b = state[1]; c = state[2]; d = state[3];
    e = state[4]; f = state[5]; g = state[6]; h = state[7];
    
    #pragma unroll 64
    for (int i = 0; i < 64; i++) {
        t1 = h + sigma1_256(e) + ch(e, f, g) + K256[i] + W[i];
        t2 = sigma0_256(a) + maj(a, b, c);
        h = g; g = f; f = e; e = d + t1;
        d = c; c = b; b = a; a = t1 + t2;
    }
    
    state[0] += a; state[1] += b; state[2] += c; state[3] += d;
    state[4] += e; state[5] += f; state[6] += g; state[7] += h;
}

__device__ void sha256(const uint8_t* data, size_t len, uint8_t* hash) {
    uint32_t state[8] = {
        0x6a09e667, 0xbb67ae85, 0x3c6ef372, 0xa54ff53a,
        0x510e527f, 0x9b05688c, 0x1f83d9ab, 0x5be0cd19
    };
    
    uint8_t buffer[64];
    size_t buffer_len = 0;
    uint64_t total_len = 0;
    
    // Processar blocos completos
    while (len >= 64) {
        sha256_transform(state, data);
        data += 64;
        len -= 64;
        total_len += 64;
    }
    
    // Copiar dados restantes
    for (size_t i = 0; i < len; i++) {
        buffer[i] = data[i];
    }
    buffer_len = len;
    total_len += len;
    
    // Padding
    buffer[buffer_len++] = 0x80;
    
    if (buffer_len > 56) {
        while (buffer_len < 64) buffer[buffer_len++] = 0;
        sha256_transform(state, buffer);
        buffer_len = 0;
    }
    
    while (buffer_len < 56) buffer[buffer_len++] = 0;
    
    // Comprimento em bits (big-endian)
    uint64_t bit_len = total_len * 8;
    buffer[56] = (bit_len >> 56) & 0xFF;
    buffer[57] = (bit_len >> 48) & 0xFF;
    buffer[58] = (bit_len >> 40) & 0xFF;
    buffer[59] = (bit_len >> 32) & 0xFF;
    buffer[60] = (bit_len >> 24) & 0xFF;
    buffer[61] = (bit_len >> 16) & 0xFF;
    buffer[62] = (bit_len >> 8) & 0xFF;
    buffer[63] = bit_len & 0xFF;
    
    sha256_transform(state, buffer);
    
    // Saída (big-endian)
    for (int i = 0; i < 8; i++) {
        hash[i * 4] = (state[i] >> 24) & 0xFF;
        hash[i * 4 + 1] = (state[i] >> 16) & 0xFF;
        hash[i * 4 + 2] = (state[i] >> 8) & 0xFF;
        hash[i * 4 + 3] = state[i] & 0xFF;
    }
}

#endif // SHA256_CUH
