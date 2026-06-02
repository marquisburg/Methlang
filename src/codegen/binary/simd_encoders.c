#include "codegen/binary/internal.h"

#include <limits.h>
#include <stdint.h>
#include <stdlib.h>
#include <string.h>
#include "codegen/binary/simd_internal.h"
/* ---- SSE2 / scalar byte encoders local to the word-count vectorizer ----
 * Kept self-contained so the (verified) instruction encodings live next to
 * the algorithm that depends on them. xmm regs used are 0..6 and GPRs are
 * rax/rcx/rdx + r8..r11, so REX.R/B handling is explicit where r8..r15 or the
 * SSE high regs would need it (here they do not, but the helpers stay
 * general). All return 1 on success, 0 on OOM. */

/* 66 0F <op> /r  — SSE2 packed op, xmm dst, xmm src (regs 0..7). */
int wcs_sse_66(BinaryCodeBuffer *b, unsigned char op,
                      int dst, int src) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

/* F3 0F 6F /r — movdqu xmm, [rcx]  (mod=00, rm=001=rcx, no disp). */
int wcs_movdqu_xmm_rcx(BinaryCodeBuffer *b, int xmm) {
  return binary_code_buffer_append_u8(b, 0xF3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x6F) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0x00 | ((xmm & 7) << 3) | 0x01));
}

/* 66 0F 6E /r — movd xmm, r32 (here src is always a low GPR 0..2,8,9). */
int wcs_movd_xmm_reg(BinaryCodeBuffer *b, int xmm, int gpr) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_emit_rex(b, 0, xmm >> 3, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x6E) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((xmm & 7) << 3) | (gpr & 7)));
}

/* 66 0F 70 /r ib — pshufd xmm, xmm, imm8. */
int wcs_pshufd(BinaryCodeBuffer *b, int dst, int src,
                      unsigned char imm) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x70) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

/* 66 0F D7 /r — pmovmskb r32, xmm. dst is a GPR (0..15), src xmm 0..7. */
int wcs_pmovmskb(BinaryCodeBuffer *b, int gpr, int xmm) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_emit_rex(b, 0, gpr >> 3, 0, xmm >> 3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0xD7) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((gpr & 7) << 3) | (xmm & 7)));
}

/* F3 0F B8 /r — popcnt r32, r32. */
int wcs_popcnt(BinaryCodeBuffer *b, int dst, int src) {
  return binary_code_buffer_append_u8(b, 0xF3) &&
         binary_emit_rex(b, 0, dst >> 3, 0, src >> 3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0xB8) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

/* 0F B6 /r — movzx r32, byte [rcx]. */
int wcs_movzx_reg_byte_rcx(BinaryCodeBuffer *b, int gpr) {
  return binary_emit_rex(b, 0, gpr >> 3, 0, 0) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0xB6) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0x00 | ((gpr & 7) << 3) | 0x01));
}

/* C1 /4 ib (shl) or /5 ib (shr) — r32, imm8. */
int wcs_shift_reg_imm(BinaryCodeBuffer *b, int gpr, int is_shr,
                             unsigned char imm) {
  return binary_emit_rex(b, 0, 0, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0xC1) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((is_shr ? 5 : 4) << 3) |
                                (gpr & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

/* 09 /r — or r32, r32  (dst |= src). */
int wcs_or_reg_reg(BinaryCodeBuffer *b, int dst, int src) {
  return binary_emit_rex(b, 0, src >> 3, 0, dst >> 3) &&
         binary_code_buffer_append_u8(b, 0x09) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src & 7) << 3) | (dst & 7)));
}

/* F7 /2 — not r32. */
int wcs_not_reg(BinaryCodeBuffer *b, int gpr) {
  return binary_emit_rex(b, 0, 0, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0xF7) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | (2 << 3) | (gpr & 7)));
}

/* 23 /r — and r32, r32 (dst &= src). */
int wcs_and_reg_reg(BinaryCodeBuffer *b, int dst, int src) {
  return binary_emit_rex(b, 0, dst >> 3, 0, src >> 3) &&
         binary_code_buffer_append_u8(b, 0x23) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

/* 89 /r — mov r32, r32 (dst = src). */
int wcs_mov_reg_reg32(BinaryCodeBuffer *b, int dst, int src) {
  return binary_emit_rex(b, 0, src >> 3, 0, dst >> 3) &&
         binary_code_buffer_append_u8(b, 0x89) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src & 7) << 3) | (dst & 7)));
}

/* B8+r id — mov r32, imm32. */
int wcs_mov_reg_imm32(BinaryCodeBuffer *b, int gpr, uint32_t imm) {
  return binary_emit_rex(b, 0, 0, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xB8 + (gpr & 7))) &&
         binary_code_buffer_append_u32(b, imm);
}

/* 48 01 /r — add r64, r64 (dst += src). */
int wcs_add_reg_reg64(BinaryCodeBuffer *b, int dst, int src) {
  return binary_emit_rex(b, 1, src >> 3, 0, dst >> 3) &&
         binary_code_buffer_append_u8(b, 0x01) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src & 7) << 3) | (dst & 7)));
}

/* 48 83 /0 ib — add r64, imm8 ; or /5 for sub. */
int wcs_addsub_reg_imm8(BinaryCodeBuffer *b, int gpr, int is_sub,
                               unsigned char imm) {
  return binary_emit_rex(b, 1, 0, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x83) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((is_sub ? 5 : 0) << 3) |
                                (gpr & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

/* 48 83 /7 ib — cmp r64, imm8 (sign-extended). */
int wcs_cmp_reg_imm8(BinaryCodeBuffer *b, int gpr, unsigned char imm) {
  return binary_emit_rex(b, 1, 0, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x83) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | (7 << 3) | (gpr & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

/* 81 /7 id — cmp r32, imm32 (used for the tail byte compares). */
int wcs_cmp_reg_imm32(BinaryCodeBuffer *b, int gpr, uint32_t imm) {
  return binary_emit_rex(b, 0, 0, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x81) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | (7 << 3) | (gpr & 7))) &&
         binary_code_buffer_append_u32(b, imm);
}

/* 85 /r — test r32, r32. */
int wcs_test_reg_reg32(BinaryCodeBuffer *b, int gpr) {
  return binary_emit_rex(b, 0, gpr >> 3, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x85) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((gpr & 7) << 3) | (gpr & 7)));
}

/* 31 /r — xor r32, r32 (zero a reg via self-xor). */
int wcs_xor_self32(BinaryCodeBuffer *b, int gpr) {
  return binary_emit_rex(b, 0, gpr >> 3, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x31) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((gpr & 7) << 3) | (gpr & 7)));
}

/* Emit a near jcc/jmp with a 32-bit rel placeholder; record the offset of the
 * displacement field so it can be patched once the target is known. cc==0
 * means an unconditional jmp (E9), otherwise 0F 8x. */
int wcs_jcc(BinaryCodeBuffer *b, unsigned char cc, size_t *disp_off) {
  if (cc == 0) {
    if (!binary_code_buffer_append_u8(b, 0xE9)) return 0;
  } else {
    if (!binary_code_buffer_append_u8(b, 0x0F) ||
        !binary_code_buffer_append_u8(b, cc))
      return 0;
  }
  *disp_off = b->size;
  return binary_code_buffer_append_u32(b, 0);
}

/* Patch a rel32 placeholder so it jumps to the current end of the buffer. */
int wcs_patch_here(BinaryCodeBuffer *b, size_t disp_off) {
  long long delta =
      (long long)b->size - (long long)(disp_off + 4);
  if (delta < INT32_MIN || delta > INT32_MAX) return 0;
  int32_t d = (int32_t)delta;
  memcpy(b->data + disp_off, &d, 4);
  return 1;
}

/* Patch a rel32 placeholder to jump backward to a recorded target offset. */
int wcs_patch_to(BinaryCodeBuffer *b, size_t disp_off,
                        size_t target) {
  long long delta = (long long)target - (long long)(disp_off + 4);
  if (delta < INT32_MIN || delta > INT32_MAX) return 0;
  int32_t d = (int32_t)delta;
  memcpy(b->data + disp_off, &d, 4);
  return 1;
}

/* 39 /r — cmp r32, r32 */
int wcs_cmp_reg_reg32(BinaryCodeBuffer *b, int dst, int src) {
  return binary_emit_rex(b, 0, src >> 3, 0, dst >> 3) &&
         binary_code_buffer_append_u8(b, 0x39) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src & 7) << 3) | (dst & 7)));
}

/* movdqu xmm, [gpr+0] */
int wcs_movdqu_xmm_mem(BinaryCodeBuffer *b, int xmm, int gpr) {
  return binary_code_buffer_append_u8(b, 0xF3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x6F) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0x00 | ((xmm & 7) << 3) | (gpr & 7)));
}

int simd_emit_prefixed_xmm_mem_disp(BinaryCodeBuffer *b, unsigned char prefix,
                                    unsigned char opcode, int xmm, int gpr,
                                    int displacement) {
  if (!b) {
    return 0;
  }

  int use_disp8 = displacement >= -128 && displacement <= 127;
  unsigned char rm = (unsigned char)(gpr & 7);
  int needs_sib = rm == (BINARY_GP_RSP & 7);
  int needs_base_disp = rm == (BINARY_GP_RBP & 7);
  unsigned char mod =
      (displacement == 0 && !needs_base_disp) ? 0 : (use_disp8 ? 1 : 2);
  unsigned char modrm =
      (unsigned char)((mod << 6) | ((xmm & 7) << 3) |
                      (needs_sib ? 4 : rm));

  if (!binary_code_buffer_append_u8(b, prefix) ||
      !binary_emit_rex(b, 0, xmm >> 3, 0, gpr >> 3) ||
      !binary_code_buffer_append_u8(b, 0x0F) ||
      !binary_code_buffer_append_u8(b, opcode) ||
      !binary_code_buffer_append_u8(b, modrm)) {
    return 0;
  }
  if (needs_sib) {
    unsigned char sib = (unsigned char)((0 << 6) | (4 << 3) | (gpr & 7));
    if (!binary_code_buffer_append_u8(b, sib)) {
      return 0;
    }
  }
  if (mod == 1) {
    return binary_code_buffer_append_u8(b, (unsigned char)(int8_t)displacement);
  }
  if (mod == 2) {
    return binary_code_buffer_append_u32(b, (uint32_t)(int32_t)displacement);
  }
  return 1;
}

int simd_emit_xmm_mem_disp(BinaryCodeBuffer *b, unsigned char opcode,
                                  int xmm, int gpr, int displacement) {
  return simd_emit_prefixed_xmm_mem_disp(b, 0xF3, opcode, xmm, gpr,
                                         displacement);
}

int simd_movdqu_xmm_mem_disp(BinaryCodeBuffer *b, int xmm, int gpr,
                                    int displacement) {
  return simd_emit_xmm_mem_disp(b, 0x6F, xmm, gpr, displacement);
}

int simd_movdqu_mem_xmm_disp(BinaryCodeBuffer *b, int gpr,
                                    int displacement, int xmm) {
  return simd_emit_xmm_mem_disp(b, 0x7F, xmm, gpr, displacement);
}

int simd_movd_xmm_mem32_disp(BinaryCodeBuffer *b, int xmm, int gpr,
                             int displacement) {
  return simd_emit_prefixed_xmm_mem_disp(b, 0x66, 0x6E, xmm, gpr,
                                         displacement);
}

/* 66 0F 7E /r - movd r32, xmm */
int wcs_movd_reg_xmm(BinaryCodeBuffer *b, int gpr, int xmm) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_emit_rex(b, 0, xmm >> 3, 0, gpr >> 3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x7E) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((xmm & 7) << 3) | (gpr & 7)));
}

/* 29 /r — sub r32, r32 (dst -= src) */
int wcs_sub_reg_reg32(BinaryCodeBuffer *b, int dst, int src) {
  return binary_emit_rex(b, 0, src >> 3, 0, dst >> 3) &&
         binary_code_buffer_append_u8(b, 0x29) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src & 7) << 3) | (dst & 7)));
}

/* 66 0F F4 /r — pmuludq xmm, xmm */
int wcs_pmuludq(BinaryCodeBuffer *b, int dst, int src) {
  return wcs_sse_66(b, 0xF4, dst, src);
}

/* 66 0F FE /r — paddd xmm, xmm */
int wcs_paddd(BinaryCodeBuffer *b, int dst, int src) {
  return wcs_sse_66(b, 0xFE, dst, src);
}

/* 66 0F 38 xx /r — SSE4.1 packed xmm ops. */
int wcs_sse_66_38(BinaryCodeBuffer *b, unsigned char op, int dst,
                         int src) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x38) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

int wcs_pmulld(BinaryCodeBuffer *b, int dst, int src) {
  return wcs_sse_66_38(b, 0x40, dst, src);
}

/* 66 0F 38 39 /r — pminsd xmm, xmm (SSE4.1) */
int wcs_pminsd(BinaryCodeBuffer *b, int dst, int src) {
  return wcs_sse_66_38(b, 0x39, dst, src);
}

/* 66 0F 38 3D /r — pmaxsd xmm, xmm (SSE4.1) */
int wcs_pmaxsd(BinaryCodeBuffer *b, int dst, int src) {
  return wcs_sse_66_38(b, 0x3D, dst, src);
}

int wcs_broadcast_i32_to_xmm(BinaryCodeBuffer *b, int xmm, int gpr) {
  return wcs_movd_xmm_reg(b, xmm, gpr) && wcs_pshufd(b, xmm, xmm, 0x00);
}

int wcs_accumulate_xmm0_i32_to_rax(BinaryCodeBuffer *b) {
  if (!wcs_sse_66(b, 0x6F, 1, 0) || !wcs_pshufd(b, 1, 0, 0xEE) ||
      !wcs_paddd(b, 0, 1) || !wcs_pshufd(b, 1, 0, 0x01) ||
      !wcs_paddd(b, 0, 1) || !wcs_movd_reg_xmm(b, BINARY_GP_R10, 0) ||
      !binary_emit_movsxd_reg_reg32(b, BINARY_GP_R10, BINARY_GP_R10) ||
      !wcs_add_reg_reg64(b, BINARY_GP_RAX, BINARY_GP_R10)) {
    return 0;
  }
  return 1;
}

int wcs_fold_xmm6_i32_sum_to_rax(BinaryCodeBuffer *b) {
  if (!wcs_sse_66(b, 0x6F, 0, 6) || !wcs_accumulate_xmm0_i32_to_rax(b)) {
    return 0;
  }
  return 1;
}

/* 66 0F 73 /2 ib — psrlq xmm, imm8 */
int wcs_psrlq_imm(BinaryCodeBuffer *b, int xmm, unsigned char imm) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x73) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | (2 << 3) | (xmm & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

/* Fixed 32x32 int32 matrix multiply — SSE2 4-column kernel, N=32. */
/* 66 0F 73 /3 ib - psrldq xmm, imm8 */
int wcs_psrldq_imm(BinaryCodeBuffer *b, int xmm, unsigned char imm) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x73) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | (3 << 3) | (xmm & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

/* 66 0F D4 /r - paddq xmm, xmm */
int wcs_paddq(BinaryCodeBuffer *b, int dst, int src) {
  return wcs_sse_66(b, 0xD4, dst, src);
}

/* 66 0F 38 28 /r - pmuldq xmm, xmm (signed dword -> qword). */
int wcs_pmuldq(BinaryCodeBuffer *b, int dst, int src) {
  return binary_code_buffer_append_u8(b, 0x66) &&
         binary_emit_rex(b, 0, dst >> 3, 0, src >> 3) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, 0x38) &&
         binary_code_buffer_append_u8(b, 0x28) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

int wcs_vex3(BinaryCodeBuffer *b, int map, int pp, int len256, int w,
                    int reg, int rm, int vvvv) {
  unsigned char b2 = (unsigned char)((((~(reg >> 3)) & 1) << 7) |
                                     (1 << 6) |
                                     (((~(rm >> 3)) & 1) << 5) |
                                     (map & 0x1F));
  unsigned char b3 = (unsigned char)(((w & 1) << 7) |
                                     (((~vvvv) & 0x0F) << 3) |
                                     ((len256 & 1) << 2) | (pp & 3));
  return binary_code_buffer_append_u8(b, 0xC4) &&
         binary_code_buffer_append_u8(b, b2) &&
         binary_code_buffer_append_u8(b, b3);
}

int wcs_avx_modrm_mem_disp(BinaryCodeBuffer *b, int reg, int base,
                                  int displacement) {
  int use_disp8 = displacement >= -128 && displacement <= 127;
  unsigned char base_low = (unsigned char)(base & 7);
  unsigned char mod = 0;
  unsigned char rm = base_low;
  if (displacement != 0 || base_low == 5) {
    mod = use_disp8 ? 1 : 2;
  }
  if (base_low == 4) {
    rm = 4;
  }
  if (!binary_code_buffer_append_u8(
          b, (unsigned char)((mod << 6) | ((reg & 7) << 3) | rm))) {
    return 0;
  }
  if (base_low == 4 &&
      !binary_code_buffer_append_u8(
          b, (unsigned char)((0 << 6) | (4 << 3) | base_low))) {
    return 0;
  }
  if (mod == 1) {
    return binary_code_buffer_append_u8(b,
                                        (unsigned char)(int8_t)displacement);
  }
  if (mod == 2 || (mod == 0 && base_low == 5)) {
    return binary_code_buffer_append_u32(b, (uint32_t)(int32_t)displacement);
  }
  return 1;
}

int wcs_avx_vpmovsxdq_ymm_mem(BinaryCodeBuffer *b, int dst, int base,
                                     int disp) {
  return wcs_vex3(b, 2, 1, 1, 0, dst, base, 0) &&
         binary_code_buffer_append_u8(b, 0x25) &&
         wcs_avx_modrm_mem_disp(b, dst, base, disp);
}

/* vmovups [base+disp], ymm (store) - VEX.256.0F.WIG 11 /r. */
int wcs_avx_vmovups_mem_ymm(BinaryCodeBuffer *b, int base, int disp,
                                   int src) {
  return wcs_vex3(b, 1, 0, 1, 0, src, base, 0) &&
         binary_code_buffer_append_u8(b, 0x11) &&
         wcs_avx_modrm_mem_disp(b, src, base, disp);
}

/* vbroadcastsd ymm, xmm - VEX.256.66.0F38.W0 19 /r (AVX2). */
int wcs_avx_vbroadcastsd_ymm_xmm(BinaryCodeBuffer *b, int dst,
                                        int src_xmm) {
  return wcs_vex3(b, 2, 1, 1, 0, dst, src_xmm, 0) &&
         binary_code_buffer_append_u8(b, 0x19) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src_xmm & 7)));
}

int wcs_avx_vmovdqu_ymm_mem(BinaryCodeBuffer *b, int dst, int base,
                                   int displacement) {
  return wcs_vex3(b, 1, 2, 1, 0, dst, base, 0) &&
         binary_code_buffer_append_u8(b, 0x6F) &&
         wcs_avx_modrm_mem_disp(b, dst, base, displacement);
}

int wcs_avx_vpaddq_ymm(BinaryCodeBuffer *b, int dst, int src1,
                              int src2) {
  return wcs_vex3(b, 1, 1, 1, 0, dst, src2, src1) &&
         binary_code_buffer_append_u8(b, 0xD4) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src2 & 7)));
}

int wcs_avx_vpxor_ymm(BinaryCodeBuffer *b, int dst, int src1,
                             int src2) {
  return wcs_vex3(b, 1, 1, 1, 0, dst, src2, src1) &&
         binary_code_buffer_append_u8(b, 0xEF) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src2 & 7)));
}

int wcs_avx_vpmuldq_ymm(BinaryCodeBuffer *b, int dst, int src1,
                               int src2) {
  return wcs_vex3(b, 2, 1, 1, 0, dst, src2, src1) &&
         binary_code_buffer_append_u8(b, 0x28) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src2 & 7)));
}

int wcs_avx_vpsrlq_ymm_imm(BinaryCodeBuffer *b, int dst, int src,
                                  unsigned char imm) {
  return wcs_vex3(b, 1, 1, 1, 0, 2, dst, src) &&
         binary_code_buffer_append_u8(b, 0x73) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | (2 << 3) | (dst & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}

int wcs_avx_vextracti128(BinaryCodeBuffer *b, int dst_xmm, int src_ymm,
                                unsigned char lane) {
  return wcs_vex3(b, 3, 1, 1, 0, src_ymm, dst_xmm, 0) &&
         binary_code_buffer_append_u8(b, 0x39) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src_ymm & 7) << 3) |
                                (dst_xmm & 7))) &&
         binary_code_buffer_append_u8(b, lane);
}

int wcs_avx_vzeroupper(BinaryCodeBuffer *b) {
  return binary_code_buffer_append_u8(b, 0xC5) &&
         binary_code_buffer_append_u8(b, 0xF8) &&
         binary_code_buffer_append_u8(b, 0x77);
}

/* ---- packed / scalar floating-point encoders for the float vectorizers ----
 * These mirror the integer helpers above but operate on IEEE-754 lanes. The
 * 256-bit AVX forms reuse wcs_vex3 + wcs_avx_modrm_mem_disp; the 128-bit SSE
 * forms reuse the generic prefixed encoders. xmm regs used by the float
 * kernels are restricted to 0..5 (all volatile under Win64) so the kernels can
 * be inlined without saving callee-saved xmm6..xmm15. */

/* 0F <op> /r — two-byte-map SSE op with no mandatory prefix (e.g. addps). */
int wcs_sse_0f(BinaryCodeBuffer *b, unsigned char op, int dst, int src) {
  return binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

/* F2 0F <op> /r — SSE op with the F2 mandatory prefix (e.g. haddps). */
int wcs_sse_f2(BinaryCodeBuffer *b, unsigned char op, int dst, int src) {
  return binary_code_buffer_append_u8(b, 0xF2) &&
         binary_code_buffer_append_u8(b, 0x0F) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7)));
}

/* VEX.256.66.0F.WIG <op> /r — packed-double 3-operand ymm op (dst=src1 OP
 * src2). pp=1 selects the 66 prefix that distinguishes pd from ps. */
int wcs_avx_vpd_ymm(BinaryCodeBuffer *b, unsigned char op, int dst,
                           int src1, int src2) {
  return wcs_vex3(b, 1, 1, 1, 0, dst, src2, src1) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src2 & 7)));
}

/* VEX.256.0F.WIG <op> /r — packed-single 3-operand ymm op (pp=0). */
int wcs_avx_vps_ymm(BinaryCodeBuffer *b, unsigned char op, int dst,
                           int src1, int src2) {
  return wcs_vex3(b, 1, 0, 1, 0, dst, src2, src1) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src2 & 7)));
}

int wcs_avx_vaddpd_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_vpd_ymm(b, 0x58, dst, s1, s2);
}
int wcs_avx_vmulpd_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_vpd_ymm(b, 0x59, dst, s1, s2);
}
int wcs_avx_vaddps_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_vps_ymm(b, 0x58, dst, s1, s2);
}
int wcs_avx_vmulps_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_vps_ymm(b, 0x59, dst, s1, s2);
}

/* vmovups ymm, [base+disp] (load) — VEX.256.0F.WIG 10. A 256-bit load is
 * data-agnostic, so this serves both pd and ps. */
int wcs_avx_vmovups_ymm_mem(BinaryCodeBuffer *b, int dst, int base,
                                    int disp) {
  return wcs_vex3(b, 1, 0, 1, 0, dst, base, 0) &&
         binary_code_buffer_append_u8(b, 0x10) &&
         wcs_avx_modrm_mem_disp(b, dst, base, disp);
}

/* vextractf128 xmm/m128, ymm, imm8 — VEX.256.66.0F3A.W0 19 /r ib. The ymm is
 * the ModRM.reg operand and the xmm destination is ModRM.rm. */
int wcs_avx_vextractf128(BinaryCodeBuffer *b, int dst_xmm, int src_ymm,
                                unsigned char lane) {
  return wcs_vex3(b, 3, 1, 1, 0, src_ymm, dst_xmm, 0) &&
         binary_code_buffer_append_u8(b, 0x19) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((src_ymm & 7) << 3) | (dst_xmm & 7))) &&
         binary_code_buffer_append_u8(b, lane);
}

/* movsd xmm, [gpr+disp] (F2 0F 10) — scalar-double load for the dot/sum tail. */
int wcs_movsd_xmm_mem(BinaryCodeBuffer *b, int xmm, int gpr, int disp) {
  return simd_emit_prefixed_xmm_mem_disp(b, 0xF2, 0x10, xmm, gpr, disp);
}
/* movsd [gpr+disp], xmm (F2 0F 11) scalar-double store. */
int wcs_movsd_mem_xmm(BinaryCodeBuffer *b, int gpr, int disp, int xmm) {
  return simd_emit_prefixed_xmm_mem_disp(b, 0xF2, 0x11, xmm, gpr, disp);
}
/* movss xmm, [gpr+disp] (F3 0F 10) — scalar-single load for the dot/sum tail. */
int wcs_movss_xmm_mem(BinaryCodeBuffer *b, int xmm, int gpr, int disp) {
  return simd_emit_prefixed_xmm_mem_disp(b, 0xF3, 0x10, xmm, gpr, disp);
}
/* movss [gpr+disp], xmm (F3 0F 11) scalar-single store. */
int wcs_movss_mem_xmm(BinaryCodeBuffer *b, int gpr, int disp, int xmm) {
  return simd_emit_prefixed_xmm_mem_disp(b, 0xF3, 0x11, xmm, gpr, disp);
}

/* Fold the four packed-double partials in ymm2 plus the scalar running total in
 * xmm3 down to a single double, returning its bit pattern in RAX. Consumes the
 * upper ymm lanes (vextractf128 + vzeroupper) before the SSE tail so no AVX
 * state leaks past the kernel. */
int wcs_reduce_pd_acc_to_rax(BinaryCodeBuffer *b) {
  return wcs_avx_vextractf128(b, 0, 2, 1) && wcs_avx_vzeroupper(b) &&
         wcs_sse_66(b, 0x58, 2, 0) &&   /* addpd  xmm2, xmm0 */
         wcs_sse_66(b, 0x7C, 2, 2) &&   /* haddpd xmm2, xmm2 -> lane0 = sum */
         binary_emit_addsd_xmm_xmm(b, BINARY_XMM3, BINARY_XMM2) &&
         binary_emit_movq_reg_xmm(b, BINARY_GP_RAX, BINARY_XMM3);
}

/* Single-precision counterpart: fold eight packed-single partials in ymm2 and
 * the scalar total in xmm3 to one float, bit pattern (zero-extended) in RAX. */
int wcs_reduce_ps_acc_to_rax(BinaryCodeBuffer *b) {
  return wcs_avx_vextractf128(b, 0, 2, 1) && wcs_avx_vzeroupper(b) &&
         wcs_sse_0f(b, 0x58, 2, 0) &&   /* addps  xmm2, xmm0 (4 partials) */
         wcs_sse_f2(b, 0x7C, 2, 2) &&   /* haddps xmm2, xmm2 -> 2 partials */
         wcs_sse_f2(b, 0x7C, 2, 2) &&   /* haddps xmm2, xmm2 -> lane0 = sum */
         binary_emit_addss_xmm_xmm(b, BINARY_XMM3, BINARY_XMM2) &&
         wcs_movd_reg_xmm(b, BINARY_GP_RAX, BINARY_XMM3);
}

/* The reduced lane lands in R9 via movd, which zero-extends; sign-extend it to
 * 64 bits so the REX.W cmp/cmov below compare signed int32 extrema correctly
 * (a negative minimum is otherwise seen as a large positive value). The gpr
 * accumulator is kept sign-extended by its callers. */
int wcs_horizontal_pminsd_to_reg(BinaryCodeBuffer *b, int xmm, int gpr) {
  return wcs_pshufd(b, 1, xmm, 0xEE) &&
         wcs_pminsd(b, xmm, 1) &&
         wcs_pshufd(b, 1, xmm, 0x01) &&
         wcs_pminsd(b, xmm, 1) &&
         wcs_movd_reg_xmm(b, BINARY_GP_R9, xmm) &&
         binary_emit_movsxd_reg_reg32(b, BINARY_GP_R9, BINARY_GP_R9) &&
         binary_emit_cmp_reg_reg(b, BINARY_GP_R9, gpr) &&
         binary_emit_cmovcc_reg_reg(b, 0x4C /* cmovl */, gpr, BINARY_GP_R9);
}

int wcs_horizontal_pmaxsd_to_reg(BinaryCodeBuffer *b, int xmm, int gpr) {
  return wcs_pshufd(b, 1, xmm, 0xEE) &&
         wcs_pmaxsd(b, xmm, 1) &&
         wcs_pshufd(b, 1, xmm, 0x01) &&
         wcs_pmaxsd(b, xmm, 1) &&
         wcs_movd_reg_xmm(b, BINARY_GP_R9, xmm) &&
         binary_emit_movsxd_reg_reg32(b, BINARY_GP_R9, BINARY_GP_R9) &&
         binary_emit_cmp_reg_reg(b, BINARY_GP_R9, gpr) &&
         binary_emit_cmovcc_reg_reg(b, 0x4F /* cmovg */, gpr, BINARY_GP_R9);
}

/* VEX.NDS.256.66.0F38.W0 <op> /r — packed-int 3-operand ymm op via the 0F38
 * map (dst = src1 OP src2). Used by the AVX2-widened integer kernels. */
int wcs_avx_0f38_ymm(BinaryCodeBuffer *b, unsigned char op, int dst,
                            int src1, int src2) {
  return wcs_vex3(b, 2, 1, 1, 0, dst, src2, src1) &&
         binary_code_buffer_append_u8(b, op) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src2 & 7)));
}
int wcs_avx_vpminsd_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_0f38_ymm(b, 0x39, dst, s1, s2);
}
int wcs_avx_vpmaxsd_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_0f38_ymm(b, 0x3D, dst, s1, s2);
}
int wcs_avx_vpmulld_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_avx_0f38_ymm(b, 0x40, dst, s1, s2);
}
/* vpshufd ymm, ymm, imm8 — VEX.256.66.0F.WIG 70 /r ib. Shuffles dwords within
 * each 128-bit lane independently (the imm selects per-lane). */
int wcs_avx_vpshufd_ymm(BinaryCodeBuffer *b, int dst, int src,
                               unsigned char imm) {
  return wcs_vex3(b, 1, 1, 1, 0, dst, src, 0) &&
         binary_code_buffer_append_u8(b, 0x70) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}
/* vperm2i128 ymm, ymm, ymm, imm8 — VEX.256.66.0F3A.W0 46 /r ib. Selects a
 * 128-bit lane from the source pair into each half of the destination. */
int wcs_avx_vperm2i128(BinaryCodeBuffer *b, int dst, int s1, int s2,
                              unsigned char imm) {
  return wcs_vex3(b, 3, 1, 1, 0, dst, s2, s1) &&
         binary_code_buffer_append_u8(b, 0x46) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (s2 & 7))) &&
         binary_code_buffer_append_u8(b, imm);
}
int wcs_avx_vpaddd_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  /* paddd lives in the legacy 0F map, not 0F38: VEX.256.66.0F.WIG FE /r. */
  return wcs_vex3(b, 1, 1, 1, 0, dst, s2, s1) &&
         binary_code_buffer_append_u8(b, 0xFE) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (s2 & 7)));
}
/* vmovdqu [base+disp], ymm (store) — VEX.256.F3.0F.WIG 7F /r. */
int wcs_avx_vmovdqu_mem_ymm(BinaryCodeBuffer *b, int base,
                                   int displacement, int src) {
  return wcs_vex3(b, 1, 2, 1, 0, src, base, 0) &&
         binary_code_buffer_append_u8(b, 0x7F) &&
         wcs_avx_modrm_mem_disp(b, src, base, displacement);
}
/* vpbroadcastd ymm, xmm — VEX.256.66.0F38.W0 58 /r (AVX2). Splats the low
 * dword of the xmm source across all eight ymm lanes. */
int wcs_avx_vpbroadcastd_ymm(BinaryCodeBuffer *b, int dst, int src_xmm) {
  return wcs_vex3(b, 2, 1, 1, 0, dst, src_xmm, 0) &&
         binary_code_buffer_append_u8(b, 0x58) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (src_xmm & 7)));
}

/* Broadcast a 32-bit GPR value across all eight lanes of a ymm register. */
int wcs_broadcast_i32_to_ymm(BinaryCodeBuffer *b, int ymm, int gpr) {
  return wcs_movd_xmm_reg(b, ymm, gpr) && wcs_avx_vpbroadcastd_ymm(b, ymm, ymm);
}

int wcs_reduce_ymm_i32_sum_to_rax(BinaryCodeBuffer *b, int src) {
  /* Fold high 128 onto low, drop AVX state, then reuse the SSE 4-lane fold
   * (which operates on xmm0 and sign-extends into RAX). */
  return wcs_avx_vextracti128(b, 0, src, 1) && wcs_avx_vzeroupper(b) &&
         wcs_paddd(b, src, 0) && wcs_sse_66(b, 0x6F, 0, src) &&
         wcs_accumulate_xmm0_i32_to_rax(b);
}

/* ---- FMA3 (VEX.DDS, 0F38 map) — fused multiply-add helpers ----
 * vfmadd231 computes ModRM.reg = (vvvv * ModRM.rm) + ModRM.reg, i.e. the
 * destination accumulates src1*src2 in one rounding step. W1 selects double
 * lanes, W0 single; len256=1 picks the ymm form, len256=0 the scalar (xmm low
 * lane) form used by the dot/affine tails. All operands here are xmm/ymm 0..7
 * so REX.R/B (encoded in the VEX prefix) stay zero. */
int wcs_avx_vfmadd231pd_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_vex3(b, 2, 1, 1, 1, dst, s2, s1) &&
         binary_code_buffer_append_u8(b, 0xB8) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (s2 & 7)));
}
int wcs_avx_vfmadd231ps_ymm(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_vex3(b, 2, 1, 1, 0, dst, s2, s1) &&
         binary_code_buffer_append_u8(b, 0xB8) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (s2 & 7)));
}
int wcs_fmadd231sd(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_vex3(b, 2, 1, 0, 1, dst, s2, s1) &&
         binary_code_buffer_append_u8(b, 0xB9) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (s2 & 7)));
}
int wcs_fmadd231ss(BinaryCodeBuffer *b, int dst, int s1, int s2) {
  return wcs_vex3(b, 2, 1, 0, 0, dst, s2, s1) &&
         binary_code_buffer_append_u8(b, 0xB9) &&
         binary_code_buffer_append_u8(
             b, (unsigned char)(0xC0 | ((dst & 7) << 3) | (s2 & 7)));
}
