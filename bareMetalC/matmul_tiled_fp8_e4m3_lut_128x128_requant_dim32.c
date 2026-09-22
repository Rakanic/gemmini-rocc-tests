// FP8 E4M3-quad (via LUT) 128x128 matmul, REQUANT output — DIM=32 (32x32 mesh), MxDim32AllGemminiRocketConfig.
// DIM=32 port of matmul_tiled_fp8_e4m3_lut_128x128_requant.c. Changes vs the DIM=16 original:
//   - DIM 16 -> 32; tile counts parameterized to the 32-deep quad mesh (one tile = 2*DIM rows x 2*DIM cols,
//     K-depth DIM) instead of the hardcoded 32/16/32.
//   - B scratchpad granularity = DIM (was K_TILE=16); b_base uses BANK_NUM*BANK_ROWS (=8192 @ DIM32).
//   - SPAD_DEST = 128 (was 0) to clear the A footprint tiles_I*tiles_K*DIM = 64.
// PROBE: reuses the DIM=16 LUT data header — the requant goldens C_proj_hw/C_scales_row are DIM-independent
// (only the BF16 accumulator golden changes with DIM, and this requant test does not check it).
#include <stdint.h>
#include <stdio.h>
#include <string.h>

#ifndef BAREMETAL
#include <sys/mman.h>
#include <stdlib.h>
#endif

#include "include/gemmini_testutils.h"
#include "include/matmul_data_mx_lut_e4m3_128x128_dim32.h"

#define TILE 16
#define DIM 32
#define VALUES_PER_BYTE 2
#define USE_LUT 1
#define MX_ALTFMT 0
#define QUANT_LUT_UPDATE_GRANULARITY 1
#define ADDR_LEN 32

typedef uint8_t out_t;

int main() {
#ifndef BAREMETAL
  if (mlockall(MCL_CURRENT | MCL_FUTURE) != 0) { perror("mlockall"); return 1; }
#endif
  static uint32_t scale_factors[MATMUL_M * MATMUL_N / 32] __attribute__((aligned(32))) = {0};
  static uint8_t C_hw[MATMUL_M / 2][MATMUL_N];
  memset(C_hw, 0, sizeof(C_hw));

  gemmini_flush(0);

  // DIM=32 quad tiling: one tile covers 2*DIM rows x 2*DIM cols, K-depth DIM (was 32/16/32 at DIM=16).
  int tiles_I = MATMUL_M / (2 * DIM);
  int tiles_K = MATMUL_K / DIM;
  int tiles_J = MATMUL_N / (2 * DIM);

  gemmini_config_st(1 * sizeof(uint64_t));
  gemmini_extended_config_st(DIM * sizeof(out_t), NO_ACTIVATION, 1);
  gemmini_mxquant_config_mvout((uint64_t)scale_factors, tiles_I, tiles_J, tiles_K, 0, 0, QUANT_LUT_UPDATE_GRANULARITY);

  // config_ex: E4M3-quad = fp8/code0 (A/B/OUT format 0) + altfmt0 + lut_en. LUT indices in, 4-bit LUT
  // indices out on the requant projection.
  ROCC_INSTRUCTION_RS1_RS2(XCUSTOM_ACC,
      ((uint64_t)acc_scale_t_to_acc_scale_t_bits((acc_scale_t)ACC_SCALE_IDENTITY) << 32)
    | ((uint64_t)(1) << 16)
    | ((uint64_t)(0) << 14)         // C (out) format = 0 (fp8); altfmt0 + lut_en selects E4M3-quad LUT
    | ((uint64_t)(0) << 12)         // B format = 0 (fp8)
    | ((uint64_t)(0) << 10)         // A format = 0 (fp8)
    | ((uint64_t)(0) << 9)
    | ((uint64_t)(0) << 8)
    | ((uint64_t)(0) << 7)
    | ((uint64_t)(MX_ALTFMT) << 6)
    | ((uint64_t)(USE_LUT) << 5)
    | ((uint64_t)(0) << 3)
    | ((uint64_t)(WEIGHT_STATIONARY) << 2)
    | CONFIG_EX,
      ((uint64_t)(1) << 48) | (0),
      k_CONFIG);

  gemmini_mx_load_lut_dt((uint64_t)&B_lut[0][0], (MATMUL_N >> QUANT_LUT_UPDATE_GRANULARITY), 0, 8);
  gemmini_mx_load_lut_dt((uint64_t)&A_lut[0][0], (MATMUL_M >> QUANT_LUT_UPDATE_GRANULARITY), 1, 8);
  gemmini_mx_load_lut_dt((uint64_t)&C_lut[0][0], (MATMUL_M >> QUANT_LUT_UPDATE_GRANULARITY), 2, 8);
  gemmini_mx_load_scales((uint64_t)&A_scales_row, sizeof(A_scales_row), 0);
  gemmini_mx_load_scales((uint64_t)&B_scales_col, sizeof(B_scales_col), 1);
  gemmini_fence();

  uint32_t a_base = 0;
  uint32_t b_base = BANK_NUM * BANK_ROWS - tiles_K * tiles_J * DIM;

  // MVIN A: HW-tiled [M/2][K], 4-bit indices nibble-packed 2 m-rows/byte; stride = MATMUL_K bytes.
  gemmini_config_ld((MATMUL_K) * sizeof(uint8_t));
  for (int i = 0; i < tiles_I; i++)
    for (int k = 0; k < tiles_K; k++) {
      uint8_t *dram_ptr = (uint8_t *)A_in_hw + i * DIM * MATMUL_K + k * DIM;
      gemmini_extended_mvin((void *) dram_ptr, a_base + (i * tiles_K + k) * DIM, DIM, DIM);
      gemmini_fence();
    }

  // MVIN B: [K][N/2], 4-bit indices; stride = MATMUL_N/2 bytes. Scratchpad granularity = DIM (was K_TILE).
  gemmini_config_ld((MATMUL_N / VALUES_PER_BYTE) * sizeof(uint8_t));
  for (int k = 0; k < tiles_K; k++)
    for (int j = 0; j < tiles_J; j++) {
      uint8_t *dram_ptr = (uint8_t *)B_in + k * DIM * (MATMUL_N / VALUES_PER_BYTE) + j * DIM;
      gemmini_extended_mvin((void *) dram_ptr, b_base + (k * tiles_J + j) * DIM, DIM, DIM);
      gemmini_fence();
    }

  int SPAD_DEST = tiles_I * tiles_K * DIM;   // clear the A footprint (128x128 dim32 = 256)
  gemmini_loop_ws_spad(tiles_I, tiles_J, tiles_K,
      0, 0, 0, a_base, BANK_NUM * BANK_ROWS, 0, SPAD_DEST,
      false, false, false, false, false,
      NO_ACTIVATION, 0, 0, false, 0x38);

  // Readback: E4M3-quad requant = 4-bit indices, 2/byte -> M*N/2 bytes -> M*N/2/DIM spad rows.
  gemmini_fence();
  gemmini_config_st(DIM * sizeof(uint8_t));
  uint8_t *c_base = (uint8_t *) C_hw;
  int total_spad_rows = MATMUL_M * MATMUL_N / 2 / DIM;
  for (int r = 0; r < total_spad_rows; r += DIM)
    gemmini_extended_mvout(c_base + r * DIM, SPAD_DEST + r, DIM, DIM);
  gemmini_fence();

  int errors = 0;
  uint8_t *hw_bytes = (uint8_t *)C_hw;
  int printed = 0;
  for (int i = 0; i < MATMUL_M / 2; i++) {
    for (int j = 0; j < MATMUL_N; j++) {
      uint8_t got = hw_bytes[i * MATMUL_N + j];
      uint8_t exp = C_proj_hw[i][j];
      if ((got & 0x0F) != (exp & 0x0F)) {
        errors++;
        if (printed++ < 40) printf("C_proj_hw[%d][%d] lo: got %x exp %x\n", i, j, got & 0xF, exp & 0xF);
      }
      if (((got >> 4) & 0x0F) != ((exp >> 4) & 0x0F)) {
        errors++;
        if (printed++ < 40) printf("C_proj_hw[%d][%d] hi: got %x exp %x\n", i, j, (got >> 4) & 0xF, (exp >> 4) & 0xF);
      }
    }
  }

  int scale_errors = 0;
  uint8_t *sf_bytes = (uint8_t *) scale_factors;
  for (int i = 0; i < MATMUL_M; i++) {
    for (int b = 0; b < MATMUL_GN; b++) {
      uint8_t got = sf_bytes[i * MATMUL_GN + b];
      uint8_t exp = C_scales_row[b][i];
      if (got != exp) {
        scale_errors++;
        if (scale_errors <= 20) printf("Scale[%d][%d] got %x exp %x\n", i, b, got, exp);
      }
    }
  }

  if (errors == 0 && scale_errors == 0)
    printf("fp8 e4m3-quad requant dim32 test PASSED (no mismatches).\n");
  else
    printf("fp8 e4m3-quad requant dim32 test FAILED: %d code, %d scale mismatches.\n", errors, scale_errors);
  return (errors == 0 && scale_errors == 0) ? 0 : 1;
}
