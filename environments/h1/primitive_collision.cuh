// CUDA primitive helpers derived from NablaEngine 70d0c8c.
// Original collision translation: MuJoCo Warp / MuJoCo, Apache-2.0;
// Copyright 2025 The Newton Developers; Copyright DeepMind Technologies Limited.
// This file retains the original float arithmetic and adds no Warp kernels.
__device__ __forceinline__ float plane_point(const float* p1, const float* n, const float* c, float r, float* pos) {
  float dist = RSUB(RSUB(dot3_rn(c, n), dot3_rn(p1, n)), r), hp = RFMA(0.5f, dist, r);
  for (int k = 0; k < 3; k++) pos[k] = RFMS(n[k], hp, c[k]);
  return dist;
}

__device__ __forceinline__ void capsule_end(const float* p, const float* axis, float hl, int e, float* ce) {
  for (int k = 0; k < 3; k++) {
    float l = RMUL(axis[k], hl);
    ce[k] = e == 0 ? RADD(p[k], l) : RSUB(p[k], l);
  }
}
