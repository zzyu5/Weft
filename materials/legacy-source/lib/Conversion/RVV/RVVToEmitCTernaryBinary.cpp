#include "RVVToEmitCInternal.h"
#include "Weft/Conversion/RVV/RVVToEmitCSupport.h"
#include "Weft/Dialect/Exec/IR/ExecOps.h"
#include "Weft/Dialect/RVV/IR/RVVDialect.h"
#include "Weft/Plugin/RVV/RVVMonolithicBlockDotFamily.h"

#include "mlir/Dialect/EmitC/IR/EmitC.h"
#include "mlir/IR/Builders.h"
#include "mlir/IR/BuiltinOps.h"
#include "mlir/IR/MLIRContext.h"
#include "mlir/Transforms/DialectConversion.h"
#include "llvm/ADT/DenseMap.h"
#include "llvm/ADT/SmallVector.h"
#include "llvm/ADT/StringRef.h"
#include "llvm/Support/raw_ostream.h"

#include <optional>
#include <string>
#include <utility>

namespace weft {
namespace conversion {
namespace rvv {
namespace detail {

// VariantToEmitCFunc ternary + binary emit methods: iq1_s / iq1_m and
// tq1_0 / tq2_0. Split out of RVVToEmitC.cpp as a pure code move; the emitted C
// is byte-identical.

// ---------------------------------------------------------------------------
// iq1_s super-block TERNARY-grid byte-exact shared emit anchors. Extracted from
// the (now-retired) monolith emitIQ1SQ8KBlockDot as a pure code move (the emitted C is
// byte-identical) so the front-door-constructed typed super-block SCALAR-grid
// loop (fold_model "scalar_delta_grid") lowers byte-identically by construction:
// same grid decl, same per-super-block body, same facts, same order.
// ---------------------------------------------------------------------------

// The fixed 2048-entry iq1_s TERNARY grid codebook as ONE `static const uint64_t
// weft_iq1s_grid[2048]` verbatim decl (ggml's exact hex literals, `0x%016llxULL`).
// The ternary entries have the high bit set (e.g. 0xffffffffffffffff = all -1),
// matching ggml's own `uint64_t iq1s_grid` type; read through a `(const int8_t *)`
// byte cast at gather time each 0xff byte yields the signed ternary value -1,
// byte-identical to ggml's grid read.
void VariantToEmitCFunc::emitIQ1SGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    llvm::ArrayRef<int64_t> grid) const {
  std::string decl = "static const uint64_t weft_iq1s_grid[2048] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[32];
    std::snprintf(buf, sizeof(buf), "0x%016llxULL",
                  static_cast<unsigned long long>(
                      static_cast<uint64_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The grid-core brick carries NO grid in the IR -- the emitter keys the fixed
// codebook off the brick op identity (milestone-2). Emit the decl from the
// CANONICAL kIQ1SGrid constant (the SAME array the monolith's grid attr is
// populated from), so the typed grid loop's decl is byte-identical to the
// monolith's `blockDot.getGrid()` decl.
void VariantToEmitCFunc::emitIQ1SCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ1SGrid;
  emitIQ1SGridTableDecl(rewriter, loc,
                        llvm::ArrayRef<int64_t>(grid.data(), grid.size()));
}

// Emit ONE iq1_s super-block's TERNARY-grid body (the fp16*fp32 d fold scale, the
// qs/qh/q8/bsums bases, the two SCALAR i32 accumulators sumi/sumi1, the flat
// 8-sub-block vluxei16 grid gather + signed widening dot, and the per-super-block
// scalar delta fold into the carried `sumf` lvalue) at the current insertion
// point INSIDE an already-open super-block loop whose per-super-block bases xb/yb
// are provided. The emitc element/pointer types + the load helpers are re-derived
// here from the MLIRContext (uniqued -> the SAME Type instances) so the emit is
// byte-identical to the monolith's inline body.
void VariantToEmitCFunc::emitIQ1SSuperBlockGridBody(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    const IQ1SGridBodyContext &cx, mlir::Value xb, mlir::Value yb,
    mlir::TypedValue<emitc::LValueType> sumfVar) const {
  mlir::MLIRContext *ctx = rewriter.getContext();
  llvm::StringRef opName = cx.opName;
  llvm::StringRef role = cx.role;
  mlir::Type sizeType = cx.sizeType;
  mlir::Type weightPtrType = cx.weightPtrType;
  mlir::Type activationPtrType = cx.activationPtrType;
  int64_t weightDOffset = cx.weightDOffset;
  int64_t qsOffset = cx.qsOffset;
  int64_t qhOffset = cx.qhOffset;
  int64_t activationDOffset = cx.activationDOffset;
  int64_t q8Offset = cx.q8Offset;
  int64_t bsumsOffset = cx.bsumsOffset;
  int64_t subBlock = cx.subBlock;
  int64_t numSubBlocks = cx.numSubBlocks;
  int64_t groupsPerSub = cx.groupsPerSub;
  mlir::Value gridArrayName = cx.gridArrayName;

  mlir::Type floatType = emitc::OpaqueType::get(ctx, "float");
  mlir::Type i32Type = emitc::OpaqueType::get(ctx, "int32_t");
  mlir::Type intType = emitc::OpaqueType::get(ctx, "int");
  mlir::Type i32m1Type = emitc::OpaqueType::get(ctx, "vint32m1_t");
  mlir::Type u16ElemType = emitc::OpaqueType::get(ctx, "uint16_t");
  mlir::Type u16mf2Type = emitc::OpaqueType::get(ctx, "vuint16mf2_t");
  mlir::Type i64m2Type = emitc::OpaqueType::get(ctx, "vint64m2_t");
  mlir::Type i8m2Type = emitc::OpaqueType::get(ctx, "vint8m2_t");
  mlir::Type i16m4Type = emitc::OpaqueType::get(ctx, "vint16m4_t");
  mlir::Type u16PtrTypeMut =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "uint16_t"));
  mlir::Type i64PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int64_t"));
  mlir::Type i8PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int8_t"));
  mlir::Type u8PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const uint8_t"));
  mlir::Type u16PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const uint16_t"));
  mlir::Type i16PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int16_t"));
  mlir::Type constU16Type = emitc::OpaqueType::get(ctx, "const uint16_t");
  mlir::Type constI16Type = emitc::OpaqueType::get(ctx, "const int16_t");
  mlir::Type constFloatType = emitc::OpaqueType::get(ctx, "const float");
  mlir::Type constFloatPtrType = emitc::PointerType::get(constFloatType);
  llvm::StringRef fp16ReadCallee = "(float)*(const _Float16 *)";

  auto sizeLit = [&](int64_t v) { return emitSizeLit(rewriter, loc, sizeType, v); };
  auto intLit = [&](int64_t v) { return emitSizeLit(rewriter, loc, intType, v); };
  auto loadByteAsInt = [&](mlir::Value ptr, int64_t i) -> mlir::Value {
    mlir::Value idx = rewriter.create<emitc::LiteralOp>(
        loc, rewriter.getIndexType(), std::to_string(i));
    mlir::Value elem =
        rewriter
            .create<emitc::SubscriptOp>(
                loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(ptr), idx)
            .getResult();
    mlir::Value u8 =
        rewriter.create<emitc::LoadOp>(loc, emitc::OpaqueType::get(ctx, "const uint8_t"), elem).getResult();
    return rewriter.create<emitc::CastOp>(loc, intType, u8).getResult();
  };
  auto loadU16AsInt = [&](mlir::Value ptr, int64_t i) -> mlir::Value {
    mlir::Value idx = rewriter.create<emitc::LiteralOp>(
        loc, rewriter.getIndexType(), std::to_string(i));
    mlir::Value elem =
        rewriter
            .create<emitc::SubscriptOp>(
                loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(ptr), idx)
            .getResult();
    mlir::Value u16 =
        rewriter.create<emitc::LoadOp>(loc, constU16Type, elem).getResult();
    return rewriter.create<emitc::CastOp>(loc, intType, u16).getResult();
  };
  auto loadI16AsInt = [&](mlir::Value ptr, int64_t i) -> mlir::Value {
    mlir::Value idx = rewriter.create<emitc::LiteralOp>(
        loc, rewriter.getIndexType(), std::to_string(i));
    mlir::Value elem =
        rewriter
            .create<emitc::SubscriptOp>(
                loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(ptr), idx)
            .getResult();
    mlir::Value i16 =
        rewriter.create<emitc::LoadOp>(loc, constI16Type, elem).getResult();
    return rewriter.create<emitc::CastOp>(loc, intType, i16).getResult();
  };

    // d = (float)*(const _Float16 *)(xb + 0) * *(const float *)(yb + 0);  (ONCE
    // per super-block; the fp16 weight scale times the fp32 q8_K scale).
    mlir::Value dxAddr = xb;
    if (weightDOffset != 0)
      dxAddr = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                             sizeLit(weightDOffset));
    mlir::Value dx = emitOpaqueCall(rewriter, loc, floatType, fp16ReadCallee,
                                    mlir::ValueRange{dxAddr}, opName, role,
                                    llvm::StringRef("fcvt.s.h"));
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "fold_activation_d"));
    mlir::Value dyAddr = yb;
    if (activationDOffset != 0)
      dyAddr = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                             sizeLit(activationDOffset));
    mlir::Value dyPtr =
        rewriter.create<emitc::CastOp>(loc, constFloatPtrType, dyAddr)
            .getResult();
    mlir::Value dyIndex0 =
        rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
    mlir::Value dyElem =
        rewriter
            .create<emitc::SubscriptOp>(
                loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(dyPtr),
                dyIndex0)
            .getResult();
    mlir::Value dy =
        rewriter.create<emitc::LoadOp>(loc, constFloatType, dyElem).getResult();
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "fold_scale_d"));
    mlir::Value d =
        rewriter.create<emitc::MulOp>(loc, floatType, dx, dy).getResult();

    // const uint8_t *qs = xb + 2;  const uint16_t *qh = xb + 34;
    // const int8_t *q8 = yb + 4;   const int16_t *bsums = yb + 260;
    mlir::Value qsBase0 = xb;
    if (qsOffset != 0)
      qsBase0 = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                              sizeLit(qsOffset));
    mlir::Value qsBase =
        rewriter.create<emitc::CastOp>(loc, u8PtrType, qsBase0).getResult();
    mlir::Value qhBase0 = xb;
    if (qhOffset != 0)
      qhBase0 = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                              sizeLit(qhOffset));
    mlir::Value qhBase =
        rewriter.create<emitc::CastOp>(loc, u16PtrType, qhBase0).getResult();
    mlir::Value q8Base0 = yb;
    if (q8Offset != 0)
      q8Base0 = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                              sizeLit(q8Offset));
    mlir::Value q8Base =
        rewriter.create<emitc::CastOp>(loc, i8PtrType, q8Base0).getResult();
    mlir::Value bsumsBase0 = yb;
    if (bsumsOffset != 0)
      bsumsBase0 = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                                 sizeLit(bsumsOffset));
    mlir::Value bsumsBase =
        rewriter.create<emitc::CastOp>(loc, i16PtrType, bsumsBase0).getResult();

    // int32_t sumi = 0;  int32_t sumi1 = 0;  (the TWO integer super-block
    // accumulators -- the grid dot and the delta-bsum term -- reset per super-block
    // and kept SEPARATE across all 8 sub-blocks; ggml's per-super-block sumi/sumi1).
    rewriter.create<emitc::VerbatimOp>(
        loc, localVariableComment("sumi", opName, role));
    auto sumiVar = rewriter.create<emitc::VariableOp>(
        loc, emitc::LValueType::get(i32Type), emitc::OpaqueAttr::get(ctx, ""));
    rewriter.create<emitc::AssignOp>(
        loc, sumiVar, rewriter.create<emitc::LiteralOp>(loc, i32Type, "0"));
    rewriter.create<emitc::VerbatimOp>(
        loc, localVariableComment("sumi1", opName, role));
    auto sumi1Var = rewriter.create<emitc::VariableOp>(
        loc, emitc::LValueType::get(i32Type), emitc::OpaqueAttr::get(ctx, ""));
    rewriter.create<emitc::AssignOp>(
        loc, sumi1Var, rewriter.create<emitc::LiteralOp>(loc, i32Type, "0"));

    // The FLAT per-sub-block loop (ib = 0..7), fully unrolled. Each sub-block has 4
    // single-byte qs index bytes (qs[ib*4 + l]), one uint16 qh word (qh[ib]) and two
    // int16 bsums (bsums[2*ib+0], bsums[2*ib+1]); the q8 cursor advances 8 per group.
    for (int64_t ib = 0; ib < numSubBlocks; ++ib) {
      // DELTA: int qhw = qh[ib];  ls = 2*((qhw>>12)&7)+1;  delta = 1 - 2*((qhw>>15)&1).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "qh_word_scale_delta"));
      mlir::Value qhWord = loadU16AsInt(qhBase, ib);

      // ls = 2*((qhw >> 12) & 7) + 1.
      mlir::Value scaleField =
          rewriter
              .create<emitc::BitwiseAndOp>(
                  loc, intType,
                  rewriter
                      .create<emitc::BitwiseRightShiftOp>(loc, intType, qhWord,
                                                          intLit(12))
                      .getResult(),
                  intLit(7))
              .getResult();
      mlir::Value ls =
          rewriter
              .create<emitc::AddOp>(
                  loc, intType,
                  rewriter
                      .create<emitc::MulOp>(loc, intType, scaleField,
                                            intLit(2))
                      .getResult(),
                  intLit(1))
              .getResult();

      // delta = 1 - 2*((qhw >> 15) & 1)   (= +1 if bit15==0, -1 if bit15==1).
      mlir::Value signBit =
          rewriter
              .create<emitc::BitwiseAndOp>(
                  loc, intType,
                  rewriter
                      .create<emitc::BitwiseRightShiftOp>(loc, intType, qhWord,
                                                          intLit(15))
                      .getResult(),
                  intLit(1))
              .getResult();
      mlir::Value delta =
          rewriter
              .create<emitc::SubOp>(
                  loc, intType, intLit(1),
                  rewriter
                      .create<emitc::MulOp>(loc, intType, signBit, intLit(2))
                      .getResult())
              .getResult();

      // The continuous q8 cursor for this sub-block's 4 groups.
      mlir::Value q8Group =
          (ib == 0)
              ? q8Base
              : rewriter
                    .create<emitc::AddOp>(loc, i8PtrType, q8Base,
                                          sizeLit(ib * subBlock))
                    .getResult();

      // int32_t lacc = 0;  (the i32m1 reduction seed for the sub-block's ternary
      // grid dot; integer add is order-free).
      std::string seedCallee = riscvIntrinsicName("vmv_v_x", 32, "m1", "i32");
      mlir::Value laccAcc = emitOpaqueCallBuilt(
          rewriter, loc, i32m1Type, seedCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            mlir::Value zeroSeed =
                rewriter.create<emitc::LiteralOp>(loc, i32Type, "0")
                    .getResult();
            return {zeroSeed, sizeLit(1)};
          });

      // uint16_t tmp[4];  (scratch holding the 4 grid byte-offset indices idx*8;
      // EEW=16 byte offsets feed the vluxei16 indexed gather. Max idx 2047 -> 2047
      // * 8 = 16376 < 65535 fits u16.)
      rewriter.create<emitc::VerbatimOp>(
          loc, localVariableComment("idxoff", opName, role));
      mlir::Type idxArrayType =
          emitc::ArrayType::get({groupsPerSub}, u16ElemType);
      auto idxVar = rewriter.create<emitc::VariableOp>(
          loc, idxArrayType, emitc::OpaqueAttr::get(ctx, ""));
      auto idxArray =
          llvm::cast<mlir::TypedValue<emitc::ArrayType>>(idxVar.getResult());

      // KEEP the 4 scalar 11-bit index computations (byte-exact, untouched), each
      // shifted <<3 to a byte offset and stored into tmp[l].
      for (int64_t l = 0; l < groupsPerSub; ++l) {
        rewriter.create<emitc::VerbatimOp>(
            loc, stepComment(opName, role, "ternary_grid_index"));
        // idx = qs[ib*4 + l] | (((qhw >> (3*l)) & 7) << 8).  The low 8 bits are a
        // single qs index byte; the high 3 bits are taken from the (3*l)-shifted qh
        // field masked to bits [8,10] (shift 0,3,6,9 for l=0,1,2,3). The whole index
        // stays within [0,2047].
        mlir::Value qsIdxByte =
            loadByteAsInt(qsBase, ib * groupsPerSub + l);
        mlir::Value qhField =
            rewriter
                .create<emitc::BitwiseAndOp>(
                    loc, intType,
                    rewriter
                        .create<emitc::BitwiseRightShiftOp>(loc, intType,
                                                            qhWord,
                                                            intLit(3 * l))
                        .getResult(),
                    intLit(7))
                .getResult();
        mlir::Value qhHighBits =
            rewriter
                .create<emitc::BitwiseLeftShiftOp>(loc, intType, qhField,
                                                   intLit(8))
                .getResult();
        mlir::Value idx =
            rewriter
                .create<emitc::BitwiseOrOp>(loc, intType, qsIdxByte,
                                            qhHighBits)
                .getResult();
        // tmp[l] = (uint16_t)(idx << 3);  (idx*8 byte offset into the u64 grid).
        mlir::Value byteOff =
            rewriter
                .create<emitc::BitwiseLeftShiftOp>(loc, intType, idx,
                                                   intLit(3))
                .getResult();
        mlir::Value byteOffU16 =
            rewriter.create<emitc::CastOp>(loc, u16ElemType, byteOff)
                .getResult();
        mlir::Value tmpIdx = rewriter.create<emitc::LiteralOp>(
            loc, rewriter.getIndexType(), std::to_string(l));
        mlir::Value tmpElem =
            rewriter
                .create<emitc::SubscriptOp>(loc, idxArray,
                                            mlir::ValueRange{tmpIdx})
                .getResult();
        rewriter.create<emitc::AssignOp>(
            loc, llvm::cast<mlir::TypedValue<emitc::LValueType>>(tmpElem),
            byteOffU16);
      }

      // vuint16mf2_t vidx = __riscv_vle16_v_u16mf2(&tmp[0], 4);  (index EMUL =
      // (EEW_idx/SEW_data)*LMUL_data = (16/64)*2 = 1/2 -> mf2 for the i64m2 gather.)
      mlir::Value idxBaseIndex0 =
          rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
      mlir::Value idxBaseElem0 =
          rewriter
              .create<emitc::SubscriptOp>(loc, idxArray,
                                          mlir::ValueRange{idxBaseIndex0})
              .getResult();
      mlir::Value idxBase =
          rewriter
              .create<emitc::ApplyOp>(loc, u16PtrTypeMut, "&", idxBaseElem0)
              .getResult();
      std::string idxLoadCallee =
          riscvIntrinsicName("vle", 16, "mf2", "u16");
      mlir::Value vidx = emitOpaqueCallBuilt(
          rewriter, loc, u16mf2Type, idxLoadCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {idxBase, sizeLit(groupsPerSub)};
          });

      // grid64 = (const int64_t *)weft_iq1s_grid;  (the u64 grid as int64 base for
      // the indexed gather -- exactly ggml's (const int64_t *)iq1s_grid.)
      mlir::Value grid64 =
          rewriter.create<emitc::CastOp>(loc, i64PtrType, gridArrayName)
              .getResult();

      // vint64m2_t g64 = __riscv_vluxei16_v_i64m2(grid64, vidx, 4);  -- the HARDWARE
      // indexed gather of the 4 grid u64 entries (ggml's __riscv_vluxei16), then
      // reinterpret to i8m2 = 32 signed ternary grid bytes.
      std::string gatherCallee =
          riscvIndexedMemoryIntrinsicName("vluxei", 16, "i64", "m2");
      mlir::Value gathered = emitOpaqueCallBuilt(
          rewriter, loc, i64m2Type, gatherCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {grid64, vidx, sizeLit(groupsPerSub)};
          });
      std::string reinterpretCallee = "__riscv_vreinterpret_v_i64m2_i8m2";
      mlir::Value gridV =
          emitOpaqueCall(rewriter, loc, i8m2Type, reinterpretCallee,
                         mlir::ValueRange{gathered}, opName, role);

      // vint8m2_t q8v = __riscv_vle8_v_i8m2(q8Group, 32);  (the full 32-lane
      // sub-block activations, one contiguous load.)
      std::string q8LoadCallee = riscvIntrinsicName("vle", 8, "m2", "i8");
      mlir::Value q8V = emitOpaqueCallBuilt(
          rewriter, loc, i8m2Type, q8LoadCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {q8Group, sizeLit(subBlock)};
          });

      // p = __riscv_vwmul_vv_i16m4(grid, q8v, 32);  (signed widening product; the
      // ternary grid bytes are ALREADY signed {-1,0,+1}, NO sign-apply.)
      std::string wmulCallee = "__riscv_vwmul_vv_i16m4";
      mlir::Value product = emitOpaqueCallBuilt(
          rewriter, loc, i16m4Type, wmulCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {gridV, q8V, sizeLit(subBlock)};
          });

      // lacc = __riscv_vwredsum_vs_i16m4_i32m1(p, lacc, 32);  -- ONE reduction per
      // sub-block (per the byte-exact guard: ls is per-sub-block). The 32-lane sum
      // over |product|<=127*32=4064 fits i32 and is integer-associative with the
      // prior 4x8-lane reductions -> byte-exact.
      std::string reduceCallee = "__riscv_vwredsum_vs_i16m4_i32m1";
      laccAcc = emitOpaqueCallBuilt(
          rewriter, loc, i32m1Type, reduceCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {product, laccAcc, sizeLit(subBlock)};
          });

      // int lsum = __riscv_vmv_x_s_i32m1_i32(laccAcc);  (extract the ternary dot of
      // this sub-block's 4 groups).
      std::string extractCallee = "__riscv_vmv_x_s_i32m1_i32";
      mlir::Value lsum =
          emitOpaqueCall(rewriter, loc, i32Type, extractCallee,
                         mlir::ValueRange{laccAcc}, opName, role);

      // sumi = sumi + ls * lsum;  (integer accumulation; order-free).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "sumi_accumulate"));
      mlir::Value lsI32 =
          rewriter.create<emitc::CastOp>(loc, i32Type, ls).getResult();
      mlir::Value sumiCur =
          rewriter.create<emitc::LoadOp>(loc, i32Type, sumiVar).getResult();
      mlir::Value lsLsum =
          rewriter.create<emitc::MulOp>(loc, i32Type, lsI32, lsum).getResult();
      mlir::Value sumiNext =
          rewriter.create<emitc::AddOp>(loc, i32Type, sumiCur, lsLsum)
              .getResult();
      rewriter.create<emitc::VerbatimOp>(
          loc, assignComment("sumi", opName, role));
      rewriter.create<emitc::AssignOp>(loc, sumiVar, sumiNext);

      // DELTA term: sumi1 = sumi1 + ls * delta * (bsums[2*ib+0] + bsums[2*ib+1]);
      // (the NEW mechanism -- a per-sub-block +-ls constant times the q8 16-element
      // sums folded in the integer domain).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "delta_bsum_accumulate"));
      mlir::Value bsum0 = loadI16AsInt(bsumsBase, 2 * ib + 0);
      mlir::Value bsum1 = loadI16AsInt(bsumsBase, 2 * ib + 1);
      mlir::Value bsumPair =
          rewriter.create<emitc::AddOp>(loc, intType, bsum0, bsum1)
              .getResult();
      mlir::Value lsDelta =
          rewriter.create<emitc::MulOp>(loc, intType, ls, delta).getResult();
      mlir::Value deltaTerm =
          rewriter.create<emitc::MulOp>(loc, intType, lsDelta, bsumPair)
              .getResult();
      mlir::Value deltaTermI32 =
          rewriter.create<emitc::CastOp>(loc, i32Type, deltaTerm).getResult();
      mlir::Value sumi1Cur =
          rewriter.create<emitc::LoadOp>(loc, i32Type, sumi1Var).getResult();
      mlir::Value sumi1Next =
          rewriter.create<emitc::AddOp>(loc, i32Type, sumi1Cur, deltaTermI32)
              .getResult();
      rewriter.create<emitc::VerbatimOp>(
          loc, assignComment("sumi1", opName, role));
      rewriter.create<emitc::AssignOp>(loc, sumi1Var, sumi1Next);
    }

    // sumf = sumf + d * ((float)sumi + 0.125f * (float)sumi1);  -- ONE
    // emitc.expression so it renders as ggml's single C statement and the compiler
    // fuses the SAME contraction under -ffp-contract=on/default/fast. The 0.125
    // (IQ1S_DELTA) is applied EXACTLY ONCE here, to (float)sumi1 only; the inner add
    // stays in the expression tree. Invoked in STRICT ascending super-block order.
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "fp32_accumulate_with_delta"));
    mlir::Value sumiFinal =
        rewriter.create<emitc::LoadOp>(loc, i32Type, sumiVar).getResult();
    mlir::Value sumi1Final =
        rewriter.create<emitc::LoadOp>(loc, i32Type, sumi1Var).getResult();
    mlir::Value sumfCur =
        rewriter.create<emitc::LoadOp>(loc, floatType, sumfVar).getResult();
    // The 0.125f (IQ1S_DELTA) literal is materialized OUTSIDE the expression region
    // (an emitc.literal is not a permitted expression-body op); it feeds the
    // expression as an operand exactly like d/sumi/sumi1.
    mlir::Value deltaConst =
        rewriter.create<emitc::LiteralOp>(loc, floatType, "0.125f");
    auto accumExpr = rewriter.create<emitc::ExpressionOp>(
        loc, floatType, /*do_not_inline=*/false);
    {
      mlir::OpBuilder::InsertionGuard exprGuard(rewriter);
      mlir::Block *exprBlock = rewriter.createBlock(&accumExpr.getRegion());
      rewriter.setInsertionPointToStart(exprBlock);
      mlir::Value sumiFloat =
          rewriter.create<emitc::CastOp>(loc, floatType, sumiFinal).getResult();
      mlir::Value sumi1Float =
          rewriter.create<emitc::CastOp>(loc, floatType, sumi1Final)
              .getResult();
      mlir::Value deltaScaled =
          rewriter.create<emitc::MulOp>(loc, floatType, deltaConst, sumi1Float)
              .getResult();
      mlir::Value inner =
          rewriter.create<emitc::AddOp>(loc, floatType, sumiFloat, deltaScaled)
              .getResult();
      mlir::Value blockTerm =
          rewriter.create<emitc::MulOp>(loc, floatType, d, inner).getResult();
      mlir::Value sumfNext =
          rewriter.create<emitc::AddOp>(loc, floatType, sumfCur, blockTerm)
              .getResult();
      rewriter.create<emitc::YieldOp>(loc, sumfNext);
    }
    rewriter.create<emitc::VerbatimOp>(
        loc, assignComment("sumf", opName, role));
    rewriter.create<emitc::AssignOp>(loc, sumfVar, accumExpr.getResult());
}

// ---------------------------------------------------------------------------
// iq1_m super-block TERNARY-grid byte-exact shared emit anchors. Extracted from
// the (now-retired) monolith emitIQ1MQ8KBlockDot as a pure code move (the emitted C
// is byte-identical) so the front-door-constructed typed super-block SCALAR-grid
// loop (fold_model "scalar_delta_grid", weight_block_stride 56) lowers byte-identically
// by construction: same grid decl, same per-super-block body, same facts, same order.
// iq1_m shares the SAME 2048 ternary iq1s_grid literals as iq1_s but decodes with a
// packed-scale fp16 reconstruct, TWO per-sub-block half scales, a half-split grid dot,
// and a per-GROUP delta (FOUR independent signs, fresh Σq8 -- NO bsums).
// ---------------------------------------------------------------------------

// The fixed 2048-entry iq1_m TERNARY grid codebook as ONE `static const uint64_t
// weft_iq1m_grid[2048]` verbatim decl (ggml's exact hex literals, `0x%016llxULL`).
// SAME literals as iq1_s (the ternary grid is a shared ggml constant); only the decl
// NAME differs so the two coexist.
void VariantToEmitCFunc::emitIQ1MGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    llvm::ArrayRef<int64_t> grid) const {
  std::string decl = "static const uint64_t weft_iq1m_grid[2048] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[32];
    std::snprintf(buf, sizeof(buf), "0x%016llxULL",
                  static_cast<unsigned long long>(
                      static_cast<uint64_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The grid-core brick carries NO grid in the IR -- the emitter keys the fixed
// codebook off the brick op identity. Emit the decl from the CANONICAL kIQ1MGrid
// constant (the SAME array the monolith's grid attr is populated from), so the typed
// grid loop's decl is byte-identical to the monolith's `blockDot.getGrid()` decl.
void VariantToEmitCFunc::emitIQ1MCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ1MGrid;
  emitIQ1MGridTableDecl(rewriter, loc,
                        llvm::ArrayRef<int64_t>(grid.data(), grid.size()));
}

// The fixed 256-entry iq3_xxs GRID-of-4 codebook as ONE `static const uint32_t
// weft_iq3xxs_grid[256]` verbatim decl (ggml's exact hex literals, `0x%08xU`). The
// byte-exact SHARED anchor kept across the iq3_xxs flip: the retired monolith
// emitIQ3XXSQ8KBlockDot rendered its carried grid attr with this SAME format; the typed
// grid loop lowering (the sole live caller) passes the canonical kIQ3XXSGrid so the
// emitted decl is byte-identical.
void VariantToEmitCFunc::emitIQ3XXSGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    llvm::ArrayRef<int32_t> grid) const {
  std::string decl = "static const uint32_t weft_iq3xxs_grid[256] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[24];
    std::snprintf(buf, sizeof(buf), "0x%08xU",
                  static_cast<unsigned>(static_cast<uint32_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The iq3_xxs grid-core brick carries NO grid in the IR -- the emitter keys the fixed
// GRID-of-4 codebook off the brick op identity. Emit the decl from the CANONICAL
// kIQ3XXSGrid constant (the SAME array the monolith's grid attr was populated from), so
// the typed grid loop's decl is byte-identical to the retired monolith's grid decl.
void VariantToEmitCFunc::emitIQ3XXSCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ3XXSGrid;
  emitIQ3XXSGridTableDecl(rewriter, loc,
                          llvm::ArrayRef<int32_t>(grid.data(), grid.size()));
}

// The fixed 128-entry ksigns_iq2xs SIGN plane as ONE `static const uint8_t
// weft_iq3xxs_ksigns[128]` verbatim decl (values reach 255, carried as i32 in the
// canonical kIQ3XXSKsigns, masked & 0xff). The byte-exact SHARED anchor kept across the
// iq3_xxs flip: the retired monolith rendered its carried ksigns attr identically; the
// typed grid loop lowering passes kIQ3XXSKsigns so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ3XXSCanonicalKsignsTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &ksigns = weft::plugin::rvv::kIQ3XXSKsigns;
  std::string decl = "static const uint8_t weft_iq3xxs_ksigns[128] = {";
  for (size_t i = 0; i < ksigns.size(); ++i) {
    if (i)
      decl += ", ";
    decl += std::to_string(static_cast<int>(ksigns[i]) & 0xff);
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The fixed 512-entry iq3_s GRID-of-4 codebook as ONE `static const uint32_t
// weft_iq3s_grid[512]` verbatim decl (ggml's exact hex literals, `0x%08xU`). The
// byte-exact SHARED anchor kept across the iq3_s flip: the retired monolith
// emitIQ3SQ8KBlockDot rendered its carried grid attr with this SAME format; the typed
// grid loop lowering (the sole live caller) passes the canonical kIQ3SGrid so the
// emitted decl is byte-identical. iq3_s is the iq3_xxs GRID-of-4 sibling with a LARGER
// (512-entry, 9-bit-index) table -- otherwise the same uint32-packed-4-int8 grid.
void VariantToEmitCFunc::emitIQ3SGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    llvm::ArrayRef<int32_t> grid) const {
  std::string decl = "static const uint32_t weft_iq3s_grid[512] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[24];
    std::snprintf(buf, sizeof(buf), "0x%08xU",
                  static_cast<unsigned>(static_cast<uint32_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The iq3_s grid-core brick carries NO grid in the IR -- the emitter keys the fixed
// GRID-of-4 codebook off the brick op identity. Emit the decl from the CANONICAL
// kIQ3SGrid constant (the SAME array the monolith's grid attr was populated from), so
// the typed grid loop's decl is byte-identical to the retired monolith's grid decl.
void VariantToEmitCFunc::emitIQ3SCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ3SGrid;
  emitIQ3SGridTableDecl(rewriter, loc,
                        llvm::ArrayRef<int32_t>(grid.data(), grid.size()));
}

// The fixed 256-entry iq2_xxs GRID-of-8 codebook as ONE `static const int64_t
// weft_iq2xxs_grid[256]` verbatim decl (ggml's exact uint64 literals rendered
// `0x%016llxULL` so the int64_t initializer carries the exact uint64 bit pattern; every
// grid byte is <= 0x2b < 128 so reading it as int8 yields the identical numeric value as
// ggml's uint8 read). The byte-exact SHARED anchor kept across the iq2_xxs flip: the
// retired monolith rendered its carried grid attr identically; the typed grid loop
// lowering passes the canonical kIQ2XXSGrid so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ2XXSCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ2XXSGrid;
  std::string decl = "static const int64_t weft_iq2xxs_grid[256] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[32];
    std::snprintf(buf, sizeof(buf), "0x%016llxULL",
                  static_cast<unsigned long long>(
                      static_cast<uint64_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The DERIVED keven_signs_q2xs signs64 SIGN plane as ONE `static const int8_t
// weft_iq2xxs_signs64[1024]` verbatim decl (128 selectors * 8 +-1 bytes). This IS the
// signs64 sign-plane MECHANISM carried by op identity (NO op-attr extension): byte b of
// selector j is `(ksigns_iq2xs[j] & (1<<b)) ? -1 : +1`, exactly the per-lane sign the
// old scalar fold computed via vmv/vand/vmsne/vneg/vmerge, so gathering signs64[sel]
// reproduces it byte-exact (0/1024 mismatch vs ggml's literal keven_signs_q2xs). The
// byte-exact SHARED anchor kept across the iq2_xxs flip: the retired monolith derived it
// identically from its carried 128-entry ksigns attr; the typed grid loop lowering passes
// the canonical kIQ2XXSKsigns so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ2XXSCanonicalSigns64TableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &ksigns = weft::plugin::rvv::kIQ2XXSKsigns;
  std::string decl = "static const int8_t weft_iq2xxs_signs64[1024] = {";
  for (size_t j = 0; j < ksigns.size(); ++j) {
    unsigned sel = static_cast<unsigned>(ksigns[j]) & 0xff;
    for (int b = 0; b < 8; ++b) {
      if (j || b)
        decl += ", ";
      decl += ((sel >> b) & 1u) ? "-1" : "1";
    }
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The fixed 512-entry iq2_xs GRID codebook as ONE `static const int64_t
// weft_iq2xs_grid[512]` verbatim decl (ggml's exact uint64 hex literals rendered
// `0x%016llxULL` so the int64_t initializer carries the exact uint64 bit pattern; every
// grid byte is <= 0x2b < 128 so reading it as int8 yields the identical numeric value as
// ggml's uint8 read). The byte-exact SHARED anchor kept across the iq2_xs flip: the retired
// monolith rendered its carried grid attr identically; the typed grid loop lowering passes
// the canonical kIQ2XSGrid so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ2XSCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ2XSGrid;
  std::string decl = "static const int64_t weft_iq2xs_grid[512] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[32];
    std::snprintf(buf, sizeof(buf), "0x%016llxULL",
                  static_cast<unsigned long long>(
                      static_cast<uint64_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The DERIVED keven_signs_q2xs signs64 SIGN plane as ONE `static const int8_t
// weft_iq2xs_signs64[1024]` verbatim decl (128 selectors * 8 +-1 bytes). This IS the
// signs64 sign-plane MECHANISM carried by op identity (NO op-attr extension): byte b of
// selector j is `(ksigns_iq2xs[j] & (1<<b)) ? -1 : +1`, exactly the per-lane sign the old
// scalar fold computed via vmv/vand/vmsne/vneg/vmerge, so gathering signs64[w>>9] reproduces
// it byte-exact. The byte-exact SHARED anchor kept across the iq2_xs flip: the retired
// monolith derived it identically from its carried 128-entry ksigns attr; the typed grid
// loop lowering passes the canonical kIQ2XSKsigns so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ2XSCanonicalSigns64TableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &ksigns = weft::plugin::rvv::kIQ2XSKsigns;
  std::string decl = "static const int8_t weft_iq2xs_signs64[1024] = {";
  for (size_t j = 0; j < ksigns.size(); ++j) {
    unsigned sel = static_cast<unsigned>(ksigns[j]) & 0xff;
    for (int b = 0; b < 8; ++b) {
      if (j || b)
        decl += ", ";
      decl += ((sel >> b) & 1u) ? "-1" : "1";
    }
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The fixed 1024-entry iq2_s GRID codebook as ONE `static const int64_t
// weft_iq2s_grid[1024]` verbatim decl (ggml's exact uint64 hex literals rendered
// `0x%016llxULL` so the int64_t initializer carries the exact uint64 bit pattern; every
// grid byte is <= 0x2b < 128 so reading it as int8 yields the identical numeric value as
// ggml's uint8 read). The byte-exact SHARED anchor kept across the iq2_s flip: the retired
// monolith rendered its carried grid attr identically; the typed grid loop lowering passes
// the canonical kIQ2SGrid so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ2SCanonicalGridTableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  const auto &grid = weft::plugin::rvv::kIQ2SGrid;
  std::string decl = "static const int64_t weft_iq2s_grid[1024] = {";
  for (size_t i = 0; i < grid.size(); ++i) {
    if (i)
      decl += ", ";
    char buf[32];
    std::snprintf(buf, sizeof(buf), "0x%016llxULL",
                  static_cast<unsigned long long>(
                      static_cast<uint64_t>(grid[i])));
    decl += buf;
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// The UNIVERSAL signs256 SIGN plane as ONE `static const int8_t
// weft_iq2s_signs256[2048]` verbatim decl (256 sign-byte values * 8 +-1 bytes). iq2_s has
// NO ksigns selector plane -- its signs are EXPLICIT bytes read straight from the sign
// region at qs+32, so the gather is indexed by the raw 8-bit sign byte DIRECTLY (0..255):
// byte b of sign byte v is `(v & (1<<b)) ? -1 : +1`, exactly the per-lane sign the old
// scalar fold computed via vmv/vand/vmsne/vneg/vmerge, so gathering signs256[v] reproduces
// it byte-exact. The byte-exact SHARED anchor kept across the iq2_s flip: the retired
// monolith emitted the SAME universal table inline (NO op-attr dependency -- the table is
// universal), so the decl is byte-identical.
void VariantToEmitCFunc::emitIQ2SCanonicalSigns256TableDecl(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc) const {
  std::string decl = "static const int8_t weft_iq2s_signs256[2048] = {";
  for (int v = 0; v < 256; ++v) {
    for (int b = 0; b < 8; ++b) {
      if (v || b)
        decl += ", ";
      decl += ((v >> b) & 1) ? "-1" : "1";
    }
  }
  decl += "};";
  rewriter.create<emitc::VerbatimOp>(loc, decl);
}

// Emit ONE iq1_m super-block's TERNARY-grid body (the packed iq1m_scale fp16
// reconstruct + the fp32 d fold scale, the qs/qh/sc/q8 bases, the two SCALAR i32
// accumulators sumi1/sumi2, the flat 8-sub-block per-half vluxei16 grid gather +
// signed widening dot with the two half scales ls1/ls2, the per-group Σq8 delta term,
// and the per-super-block scalar delta fold into the carried `sumf` lvalue) at the
// current insertion point INSIDE an already-open super-block loop whose per-super-block
// bases xb/yb are provided. The emitc element/pointer types + the load helpers are
// re-derived here from the MLIRContext (uniqued -> the SAME Type instances) so the emit
// is byte-identical to the monolith's inline body.
void VariantToEmitCFunc::emitIQ1MSuperBlockGridBody(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    const IQ1MGridBodyContext &cx, mlir::Value xb, mlir::Value yb,
    mlir::TypedValue<emitc::LValueType> sumfVar) const {
  mlir::MLIRContext *ctx = rewriter.getContext();
  llvm::StringRef opName = cx.opName;
  llvm::StringRef role = cx.role;
  mlir::Type sizeType = cx.sizeType;
  mlir::Type weightPtrType = cx.weightPtrType;
  mlir::Type activationPtrType = cx.activationPtrType;
  int64_t qsOffset = cx.qsOffset;                       //   0
  int64_t qhOffset = cx.qhOffset;                       //  32
  int64_t scalesOffset = cx.scalesOffset;               //  48
  int64_t activationDOffset = cx.activationDOffset;     //   0
  int64_t q8Offset = cx.q8Offset;                       //   4
  int64_t subBlock = cx.subBlock;                       //  32
  int64_t numSubBlocks = cx.numSubBlocks;               //   8
  int64_t groupsPerSub = cx.groupsPerSub;               //   4
  int64_t groupLanes = 8;    // 8 grid values per group
  mlir::Value gridArrayName = cx.gridArrayName;

  mlir::Type floatType = emitc::OpaqueType::get(ctx, "float");
  mlir::Type i32Type = emitc::OpaqueType::get(ctx, "int32_t");
  mlir::Type intType = emitc::OpaqueType::get(ctx, "int");
  mlir::Type u16Type = emitc::OpaqueType::get(ctx, "uint16_t");

  llvm::StringRef coreLmul = "m1";
  llvm::StringRef wideLmul = "m2";
  mlir::Type i8CoreType = emitc::OpaqueType::get(ctx, "vint8m1_t");
  mlir::Type i16WideType = emitc::OpaqueType::get(ctx, "vint16m2_t");
  mlir::Type i16m1Type = emitc::OpaqueType::get(ctx, "vint16m1_t");
  mlir::Type i32m1Type = emitc::OpaqueType::get(ctx, "vint32m1_t");

  int64_t halvesPerSub = 2;     // 2 halves (h=0,1) per sub-block
  int64_t groupsPerHalf = 2;    // 2 grid groups per half
  int64_t halfLanes = 16;       // 16 ternary grid bytes per half
  mlir::Type u16ElemType = emitc::OpaqueType::get(ctx, "uint16_t");
  mlir::Type u16mf4Type = emitc::OpaqueType::get(ctx, "vuint16mf4_t");
  mlir::Type i64m1Type = emitc::OpaqueType::get(ctx, "vint64m1_t");
  mlir::Type i8HalfType = i8CoreType;     // vint8m1_t (16 grid bytes per half)
  mlir::Type i16HalfType = i16WideType;   // vint16m2_t (16-lane products)
  mlir::Type u16PtrTypeMut =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "uint16_t"));
  mlir::Type i64PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int64_t"));

  auto sizeLit = [&](int64_t v) { return emitSizeLit(rewriter, loc, sizeType, v); };
  auto intLit = [&](int64_t v) { return emitSizeLit(rewriter, loc, intType, v); };

  mlir::Type i8PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int8_t"));
  mlir::Type u8PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const uint8_t"));
  mlir::Type u16PtrType =
      emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const uint16_t"));
  mlir::Type u16LValuePtrType = emitc::PointerType::get(u16Type);
  mlir::Type constU16Type = emitc::OpaqueType::get(ctx, "const uint16_t");
  mlir::Type constFloatType = emitc::OpaqueType::get(ctx, "const float");
  mlir::Type constFloatPtrType = emitc::PointerType::get(constFloatType);
  llvm::StringRef fp16ReadCallee = "(float)*(const _Float16 *)";

  // int x = (int)a[i];  -- a structured byte load from a `const uint8_t *` then a
  // cast to int (a single qs index byte or a uint8 qh byte; positive so no
  // sign-extension hazard).
  auto loadByteAsInt = [&](mlir::Value ptr, int64_t i) -> mlir::Value {
    mlir::Value idx = rewriter.create<emitc::LiteralOp>(
        loc, rewriter.getIndexType(), std::to_string(i));
    mlir::Value elem =
        rewriter
            .create<emitc::SubscriptOp>(
                loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(ptr), idx)
            .getResult();
    mlir::Value u8 =
        rewriter
            .create<emitc::LoadOp>(
                loc, emitc::OpaqueType::get(ctx, "const uint8_t"), elem)
            .getResult();
    return rewriter.create<emitc::CastOp>(loc, intType, u8).getResult();
  };

  // int x = (int)sc[i];  -- a structured uint16 load from a `const uint16_t *` then
  // a cast to int (one of the 4 packed scales[] words; carries the fp16 d
  // high-nibble AND the per-sub-block 3-bit scales low-bits; all positive).
  auto loadU16AsInt = [&](mlir::Value ptr, int64_t i) -> mlir::Value {
    mlir::Value idx = rewriter.create<emitc::LiteralOp>(
        loc, rewriter.getIndexType(), std::to_string(i));
    mlir::Value elem =
        rewriter
            .create<emitc::SubscriptOp>(
                loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(ptr), idx)
            .getResult();
    mlir::Value u16 =
        rewriter.create<emitc::LoadOp>(loc, constU16Type, elem).getResult();
    return rewriter.create<emitc::CastOp>(loc, intType, u16).getResult();
  };

  // const uint8_t *qs = xb + 0;  const uint8_t *qh = xb + 32;
  // const uint16_t *sc = (const uint16_t *)(xb + 48);  const int8_t *q8 = yb + 4;
  mlir::Value qsBase0 = xb;
  if (qsOffset != 0)
    qsBase0 = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                            sizeLit(qsOffset));
  mlir::Value qsBase =
      rewriter.create<emitc::CastOp>(loc, u8PtrType, qsBase0).getResult();
  mlir::Value qhBase0 = xb;
  if (qhOffset != 0)
    qhBase0 = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                            sizeLit(qhOffset));
  mlir::Value qhBase =
      rewriter.create<emitc::CastOp>(loc, u8PtrType, qhBase0).getResult();
  mlir::Value scBase0 = xb;
  if (scalesOffset != 0)
    scBase0 = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                            sizeLit(scalesOffset));
  mlir::Value scBase =
      rewriter.create<emitc::CastOp>(loc, u16PtrType, scBase0).getResult();
  mlir::Value q8Base0 = yb;
  if (q8Offset != 0)
    q8Base0 = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                            sizeLit(q8Offset));
  mlir::Value q8Base =
      rewriter.create<emitc::CastOp>(loc, i8PtrType, q8Base0).getResult();

  // (a) RECONSTRUCT the packed iq1m_scale fp16 super-block scale (the NEW piece).
  // scbits = (sc[0]>>12) | ((sc[1]>>8)&0xf0) | ((sc[2]>>4)&0xf00) | (sc[3]&0xf000)
  // then READ the 16 bits AS _Float16 (a bit reinterpret -- ggml's union -- NOT a
  // numeric conversion). The reassembled bits are written into a uint16_t lvalue
  // and read via the address-of so the `(const _Float16 *)` cast is byte-identical.
  rewriter.create<emitc::VerbatimOp>(
      loc, stepComment(opName, role, "iq1m_scale_reconstruct"));
  mlir::Value sc0 = loadU16AsInt(scBase, 0);
  mlir::Value sc1 = loadU16AsInt(scBase, 1);
  mlir::Value sc2 = loadU16AsInt(scBase, 2);
  mlir::Value sc3 = loadU16AsInt(scBase, 3);
  // (sc[0] >> 12)
  mlir::Value t0 =
      rewriter
          .create<emitc::BitwiseRightShiftOp>(loc, intType, sc0, intLit(12))
          .getResult();
  // ((sc[1] >> 8) & 0x00f0)
  mlir::Value t1 =
      rewriter
          .create<emitc::BitwiseAndOp>(
              loc, intType,
              rewriter
                  .create<emitc::BitwiseRightShiftOp>(loc, intType, sc1,
                                                      intLit(8))
                  .getResult(),
              intLit(0xf0))
          .getResult();
  // ((sc[2] >> 4) & 0x0f00)
  mlir::Value t2 =
      rewriter
          .create<emitc::BitwiseAndOp>(
              loc, intType,
              rewriter
                  .create<emitc::BitwiseRightShiftOp>(loc, intType, sc2,
                                                      intLit(4))
                  .getResult(),
              intLit(0xf00))
          .getResult();
  // (sc[3] & 0xf000)
  mlir::Value t3 =
      rewriter
          .create<emitc::BitwiseAndOp>(loc, intType, sc3, intLit(0xf000))
          .getResult();
  mlir::Value scbitsInt =
      rewriter
          .create<emitc::BitwiseOrOp>(
              loc, intType,
              rewriter
                  .create<emitc::BitwiseOrOp>(
                      loc, intType,
                      rewriter
                          .create<emitc::BitwiseOrOp>(loc, intType, t0, t1)
                          .getResult(),
                      t2)
                  .getResult(),
              t3)
          .getResult();
  // uint16_t scbits = (uint16_t)(...);  -- a uint16 lvalue holding the fp16 bits.
  auto scbitsVar = rewriter.create<emitc::VariableOp>(
      loc, emitc::LValueType::get(u16Type), emitc::OpaqueAttr::get(ctx, ""));
  mlir::Value scbitsU16 =
      rewriter.create<emitc::CastOp>(loc, u16Type, scbitsInt).getResult();
  rewriter.create<emitc::AssignOp>(loc, scbitsVar, scbitsU16);
  // &scbits  -> read (float)*(const _Float16 *)(&scbits).
  mlir::Value scbitsAddr =
      rewriter
          .create<emitc::ApplyOp>(loc, u16LValuePtrType,
                                  rewriter.getStringAttr("&"), scbitsVar)
          .getResult();
  mlir::Value dx =
      rewriter
          .create<emitc::CallOpaqueOp>(loc, mlir::TypeRange{floatType},
                                       fp16ReadCallee,
                                       mlir::ValueRange{scbitsAddr})
          .getResult(0);

  // d = dx * *(const float *)(yb + 0);  (the reconstructed fp16 weight scale times
  // the fp32 q8_K scale, ONE mul).
  rewriter.create<emitc::VerbatimOp>(
      loc, stepComment(opName, role, "fold_activation_d"));
  mlir::Value dyAddr = yb;
  if (activationDOffset != 0)
    dyAddr = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                           sizeLit(activationDOffset));
  mlir::Value dyPtr =
      rewriter.create<emitc::CastOp>(loc, constFloatPtrType, dyAddr)
          .getResult();
  mlir::Value dyIndex0 =
      rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
  mlir::Value dyElem =
      rewriter
          .create<emitc::SubscriptOp>(
              loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(dyPtr),
              dyIndex0)
          .getResult();
  mlir::Value dy =
      rewriter.create<emitc::LoadOp>(loc, constFloatType, dyElem).getResult();
  rewriter.create<emitc::VerbatimOp>(
      loc, stepComment(opName, role, "fold_scale_d"));
  mlir::Value d =
      rewriter.create<emitc::MulOp>(loc, floatType, dx, dy).getResult();

  // int32_t sumi1 = 0;  int32_t sumi2 = 0;  (the TWO integer super-block
  // accumulators -- the grid dot and the per-group delta term -- reset per
  // super-block and kept SEPARATE across all 8 sub-blocks; ggml's sumi1/sumi2).
  rewriter.create<emitc::VerbatimOp>(
      loc, localVariableComment("sumi1", opName, role));
  auto sumi1Var = rewriter.create<emitc::VariableOp>(
      loc, emitc::LValueType::get(i32Type), emitc::OpaqueAttr::get(ctx, ""));
  rewriter.create<emitc::AssignOp>(
      loc, sumi1Var, rewriter.create<emitc::LiteralOp>(loc, i32Type, "0"));
  rewriter.create<emitc::VerbatimOp>(
      loc, localVariableComment("sumi2", opName, role));
  auto sumi2Var = rewriter.create<emitc::VariableOp>(
      loc, emitc::LValueType::get(i32Type), emitc::OpaqueAttr::get(ctx, ""));
  rewriter.create<emitc::AssignOp>(
      loc, sumi2Var, rewriter.create<emitc::LiteralOp>(loc, i32Type, "0"));

  // The FLAT per-sub-block loop (ib = 0..7), fully unrolled. Each sub-block has 4
  // single-byte qs index bytes (qs[ib*4 + l]), TWO uint8 qh bytes (qh[2*ib+0],
  // qh[2*ib+1]) carrying the index-high fields + delta signs, and one packed
  // scales word sc[ib/2]; the q8 cursor advances 8 per group.
  for (int64_t ib = 0; ib < numSubBlocks; ++ib) {
    // int qh0 = qh[2*ib + 0];  int qh1 = qh[2*ib + 1].
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "qh_bytes_delta"));
    mlir::Value qh0 = loadByteAsInt(qhBase, 2 * ib + 0);
    mlir::Value qh1 = loadByteAsInt(qhBase, 2 * ib + 1);

    // delta[l] = 1 - 2*((qh[l/2] >> (l%2 ? 7 : 3)) & 1)  (= +1/-1). For l=0,1 use
    // qh0 (bits 3,7); for l=2,3 use qh1 (bits 3,7). Mirrors ggml's
    // delta[0]=qh0&8, delta[1]=qh0&0x80, delta[2]=qh1&8, delta[3]=qh1&0x80.
    auto deltaSign = [&](mlir::Value qhByte, int64_t bit) -> mlir::Value {
      mlir::Value b =
          rewriter
              .create<emitc::BitwiseAndOp>(
                  loc, intType,
                  rewriter
                      .create<emitc::BitwiseRightShiftOp>(loc, intType,
                                                          qhByte, intLit(bit))
                      .getResult(),
                  intLit(1))
              .getResult();
      return rewriter
          .create<emitc::SubOp>(
              loc, intType, intLit(1),
              rewriter.create<emitc::MulOp>(loc, intType, b, intLit(2))
                  .getResult())
          .getResult();
    };
    mlir::Value delta[4] = {deltaSign(qh0, 3), deltaSign(qh0, 7),
                            deltaSign(qh1, 3), deltaSign(qh1, 7)};

    // The continuous q8 cursor for this sub-block's 4 groups.
    mlir::Value q8Group =
        (ib == 0)
            ? q8Base
            : rewriter
                  .create<emitc::AddOp>(loc, i8PtrType, q8Base,
                                        sizeLit(ib * subBlock))
                  .getResult();

    // The TWO per-half integer accumulators sum1[h] (grid dot) and sum2[h]
    // (delta term), h = 0 (groups 0..1), h = 1 (groups 2..3). They are plain int
    // lvalues holding scalar reductions (the generic's sum1[2]/sum2[2]).
    auto makeIntVar = [&](const char *name) {
      rewriter.create<emitc::VerbatimOp>(
          loc, localVariableComment(name, opName, role));
      auto v = rewriter.create<emitc::VariableOp>(
          loc, emitc::LValueType::get(i32Type),
          emitc::OpaqueAttr::get(ctx, ""));
      rewriter.create<emitc::AssignOp>(
          loc, v, rewriter.create<emitc::LiteralOp>(loc, i32Type, "0"));
      return v;
    };
    emitc::VariableOp sum1Var[2] = {makeIntVar("sum1_0"),
                                    makeIntVar("sum1_1")};
    emitc::VariableOp sum2Var[2] = {makeIntVar("sum2_0"),
                                    makeIntVar("sum2_1")};

    // uint16_t idxoff[4];  -- scratch holding the 4 grid byte offsets idx*8
    // (EEW=16 byte offsets feed the vluxei16 indexed gather; max idx 2047 ->
    // 2047*8 = 16376 < 65535 fits u16). The 4 scalar 11-bit index
    // computations are KEPT byte-exact (unchanged); only the destination
    // changes from a `grid_i8 + idx*8` pointer to a stored byte offset.
    rewriter.create<emitc::VerbatimOp>(
        loc, localVariableComment("idxoff", opName, role));
    mlir::Type idxArrayType =
        emitc::ArrayType::get({groupsPerSub}, u16ElemType);
    auto idxVar = rewriter.create<emitc::VariableOp>(
        loc, idxArrayType, emitc::OpaqueAttr::get(ctx, ""));
    auto idxArray =
        llvm::cast<mlir::TypedValue<emitc::ArrayType>>(idxVar.getResult());

    // The per-group index + delta loop (l=0..3): compute the byte offset
    // idxoff[l] and the grid-INDEPENDENT sum2/delta term EXACTLY as before
    // (the delta path is untouched -- it does NOT consume the grid gather).
    for (int64_t l = 0; l < groupsPerSub; ++l) {
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "ternary_grid_index"));
      // idx = qs[ib*4 + l] | (((qh[l/2]) << (8 - 4*(l%2))) & 0x700). The index-high
      // 3 bits come from bits 0..2 of qh[l/2] for even l (shift 8) and bits 4..6
      // for odd l (shift 4). qhSel selects qh0 (l<2) or qh1 (l>=2).
      mlir::Value qhSel = (l < 2) ? qh0 : qh1;
      int64_t sh = (l % 2) ? 4 : 8;
      mlir::Value qsIdxByte =
          loadByteAsInt(qsBase, ib * groupsPerSub + l);
      mlir::Value qhHighBits =
          rewriter
              .create<emitc::BitwiseAndOp>(
                  loc, intType,
                  rewriter
                      .create<emitc::BitwiseLeftShiftOp>(loc, intType, qhSel,
                                                         intLit(sh))
                      .getResult(),
                  intLit(0x700))
              .getResult();
      mlir::Value idx =
          rewriter
              .create<emitc::BitwiseOrOp>(loc, intType, qsIdxByte,
                                          qhHighBits)
              .getResult();
      // idxoff[l] = (uint16_t)(idx << 3);  (idx*8 byte offset into the u64 grid).
      mlir::Value byteOff =
          rewriter
              .create<emitc::BitwiseLeftShiftOp>(loc, intType, idx,
                                                 intLit(3))
              .getResult();
      mlir::Value byteOffU16 =
          rewriter.create<emitc::CastOp>(loc, u16ElemType, byteOff)
              .getResult();
      mlir::Value tmpIdx = rewriter.create<emitc::LiteralOp>(
          loc, rewriter.getIndexType(), std::to_string(l));
      mlir::Value tmpElem =
          rewriter
              .create<emitc::SubscriptOp>(loc, idxArray,
                                          mlir::ValueRange{tmpIdx})
              .getResult();
      rewriter.create<emitc::AssignOp>(
          loc, llvm::cast<mlir::TypedValue<emitc::LValueType>>(tmpElem),
          byteOffU16);

      // --- sum2/delta term (grid-INDEPENDENT, UNCHANGED) ---------------
      // __riscv_vsetvl_e8m1(8);  (the group is 8 elements; m1 covers it).
      std::string innerSetvlCallee =
          riscvIntrinsicName("vsetvl", 8, "m1", "");
      mlir::Value vl = emitOpaqueCallBuilt(
          rewriter, loc, sizeType, innerSetvlCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {sizeLit(groupLanes)};
          });

      // q8_v = vle8_v_i8m1(q8Group, vl);  (the group's 8 activations).
      std::string i8LoadCallee =
          riscvIntrinsicName("vle", 8, coreLmul, "i8");
      mlir::Value q8V =
          emitOpaqueCall(rewriter, loc, i8CoreType, i8LoadCallee,
                         mlir::ValueRange{q8Group, vl}, opName, role);

      // lsum2 = vwredsum(q8_v, seed=0):  the Σq8 over the 8 activations (the
      // per-group delta term -- iq1_m's four independent group signs make the
      // bsums unusable, so the q8 sum is reduced fresh from the loaded vector).
      // i8 -> i16 widening reduce (|Σ| <= 8*127 = 1016 fits i16).
      std::string seed16Callee = riscvIntrinsicName("vmv_v_x", 16, "m1", "i16");
      mlir::Type i16Type = emitc::OpaqueType::get(ctx, "int16_t");
      mlir::Value seed16 = emitOpaqueCallBuilt(
          rewriter, loc, i16m1Type, seed16Callee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            mlir::Value zero16 =
                rewriter.create<emitc::LiteralOp>(loc, i16Type, "0")
                    .getResult();
            return {zero16, sizeLit(1)};
          });
      std::string q8ReduceCallee = "__riscv_vwredsum_vs_i8m1_i16m1";
      mlir::Value lsum2Acc =
          emitOpaqueCall(rewriter, loc, i16m1Type, q8ReduceCallee,
                         mlir::ValueRange{q8V, seed16, vl}, opName, role);
      std::string extract16Callee = "__riscv_vmv_x_s_i16m1_i16";
      mlir::Value lsum2I16 =
          emitOpaqueCall(rewriter, loc, intType, extract16Callee,
                         mlir::ValueRange{lsum2Acc}, opName, role);

      // sum2[l/2] += lsum2 * delta[l];  (scalar accumulate; order-free).
      int64_t h = l / 2;
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "sum2_delta_accumulate"));
      mlir::Value lsum2Delta =
          rewriter.create<emitc::MulOp>(loc, intType, lsum2I16, delta[l])
              .getResult();
      mlir::Value lsum2DeltaI32 =
          rewriter.create<emitc::CastOp>(loc, i32Type, lsum2Delta)
              .getResult();
      mlir::Value sum2Cur =
          rewriter.create<emitc::LoadOp>(loc, i32Type, sum2Var[h])
              .getResult();
      mlir::Value sum2Next =
          rewriter.create<emitc::AddOp>(loc, i32Type, sum2Cur, lsum2DeltaI32)
              .getResult();
      rewriter.create<emitc::AssignOp>(loc, sum2Var[h], sum2Next);

      // q8Group += 8 (advance to the next group's 8 activations).
      q8Group =
          rewriter
              .create<emitc::AddOp>(loc, i8PtrType, q8Group,
                                    sizeLit(groupLanes))
              .getResult();
    }

    // --- grid dot via vluxei16, per HALF (h=0,1) -----------------------
    // The half h covers groups {2h, 2h+1} = 16 contiguous q8 activations
    // starting at q8Base + ib*32 + h*16. For each half: gather 2 grid u64
    // entries (idxoff[2h], idxoff[2h+1]) -> i8m1 (16 grid bytes), load the
    // 16 q8, vwmul i16m2, ONE vwredsum -> sum1[h] (assigned ONCE; the 16-lane
    // reduce equals Σ(group 2h) + Σ(group 2h+1), integer-identical to the
    // original two 8-lane reduces summed into sum1[h]).
    mlir::Value grid64 =
        rewriter.create<emitc::CastOp>(loc, i64PtrType, gridArrayName)
            .getResult();
    mlir::Value q8SubBase =
        (ib == 0)
            ? q8Base
            : rewriter
                  .create<emitc::AddOp>(loc, i8PtrType, q8Base,
                                        sizeLit(ib * subBlock))
                  .getResult();
    for (int64_t h = 0; h < halvesPerSub; ++h) {
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "ternary_grid_gather_half"));

      // vuint16mf4_t vidx = __riscv_vle16_v_u16mf4(&idxoff[2h], 2);  (index
      // EMUL = (16/64)*1 = 1/4 -> mf4 for the i64m1 gather.)
      mlir::Value idxBaseIndex =
          rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(),
                                            std::to_string(h * groupsPerHalf));
      mlir::Value idxBaseElem =
          rewriter
              .create<emitc::SubscriptOp>(loc, idxArray,
                                          mlir::ValueRange{idxBaseIndex})
              .getResult();
      mlir::Value idxBase =
          rewriter
              .create<emitc::ApplyOp>(loc, u16PtrTypeMut, "&", idxBaseElem)
              .getResult();
      std::string idxLoadCallee =
          riscvIntrinsicName("vle", 16, "mf4", "u16");
      mlir::Value vidx = emitOpaqueCallBuilt(
          rewriter, loc, u16mf4Type, idxLoadCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {idxBase, sizeLit(groupsPerHalf)};
          });

      // vint64m1_t g64 = __riscv_vluxei16_v_i64m1(grid64, vidx, 2);  -- the
      // HARDWARE indexed gather of the 2 grid u64 entries (ggml's
      // __riscv_vluxei16), then reinterpret to i8m1 = 16 signed ternary bytes.
      std::string gatherCallee =
          riscvIndexedMemoryIntrinsicName("vluxei", 16, "i64", "m1");
      mlir::Value gathered = emitOpaqueCallBuilt(
          rewriter, loc, i64m1Type, gatherCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {grid64, vidx, sizeLit(groupsPerHalf)};
          });
      std::string reinterpretCallee = "__riscv_vreinterpret_v_i64m1_i8m1";
      mlir::Value gridV =
          emitOpaqueCall(rewriter, loc, i8HalfType, reinterpretCallee,
                         mlir::ValueRange{gathered}, opName, role);

      // q8h = vle8_v_i8m1(q8SubBase + h*16, 16);  (the half's 16 activations).
      mlir::Value q8HalfPtr =
          (h == 0)
              ? q8SubBase
              : rewriter
                    .create<emitc::AddOp>(loc, i8PtrType, q8SubBase,
                                          sizeLit(h * halfLanes))
                    .getResult();
      std::string q8LoadCallee = riscvIntrinsicName("vle", 8, coreLmul, "i8");
      mlir::Value q8H = emitOpaqueCallBuilt(
          rewriter, loc, i8HalfType, q8LoadCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {q8HalfPtr, sizeLit(halfLanes)};
          });

      // p = __riscv_vwmul_vv_i16m2(grid, q8h, 16);  (signed widening product;
      // the ternary grid bytes are ALREADY signed {-1,0,+1}, so NO sign apply.)
      std::string wmulCallee = ("__riscv_vwmul_vv_i16" + wideLmul).str();
      mlir::Value product = emitOpaqueCallBuilt(
          rewriter, loc, i16HalfType, wmulCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {gridV, q8H, sizeLit(halfLanes)};
          });

      // sum1[h] = __riscv_vmv_x_s(vwredsum_vs_i16m2_i32m1(p, seed=0, 16));
      // -- ONE reduction per half; assigned ONCE (no +=) since the whole
      // half is computed in a single shot.
      std::string seed32Callee = riscvIntrinsicName("vmv_v_x", 32, "m1", "i32");
      mlir::Value seed32 = emitOpaqueCallBuilt(
          rewriter, loc, i32m1Type, seed32Callee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            mlir::Value zero32 =
                rewriter.create<emitc::LiteralOp>(loc, i32Type, "0")
                    .getResult();
            return {zero32, sizeLit(1)};
          });
      std::string reduceCallee =
          ("__riscv_vwredsum_vs_i16" + wideLmul + "_i32m1").str();
      mlir::Value sum1Acc = emitOpaqueCallBuilt(
          rewriter, loc, i32m1Type, reduceCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {product, seed32, sizeLit(halfLanes)};
          });
      std::string extract32Callee = "__riscv_vmv_x_s_i32m1_i32";
      mlir::Value sum1H =
          emitOpaqueCall(rewriter, loc, i32Type, extract32Callee,
                         mlir::ValueRange{sum1Acc}, opName, role);
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "sum1_assign"));
      rewriter.create<emitc::AssignOp>(loc, sum1Var[h], sum1H);
    }

    // ls1 = 2*((sc[ib/2] >> (6*(ib%2)+0)) & 7) + 1;  (groups 0..1)
    // ls2 = 2*((sc[ib/2] >> (6*(ib%2)+3)) & 7) + 1;  (groups 2..3)
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "per_half_scale"));
    mlir::Value scWord = loadU16AsInt(scBase, ib / 2);
    int64_t baseShift = 6 * (ib % 2);
    auto scaleFromBits = [&](int64_t shift) -> mlir::Value {
      mlir::Value field =
          rewriter
              .create<emitc::BitwiseAndOp>(
                  loc, intType,
                  rewriter
                      .create<emitc::BitwiseRightShiftOp>(
                          loc, intType, scWord, intLit(shift))
                      .getResult(),
                  intLit(7))
              .getResult();
      return rewriter
          .create<emitc::AddOp>(
              loc, intType,
              rewriter.create<emitc::MulOp>(loc, intType, field, intLit(2))
                  .getResult(),
              intLit(1))
          .getResult();
    };
    mlir::Value ls1 = scaleFromBits(baseShift + 0);
    mlir::Value ls2 = scaleFromBits(baseShift + 3);
    mlir::Value ls1I32 =
        rewriter.create<emitc::CastOp>(loc, i32Type, ls1).getResult();
    mlir::Value ls2I32 =
        rewriter.create<emitc::CastOp>(loc, i32Type, ls2).getResult();

    // sumi1 += sum1[0]*ls1 + sum1[1]*ls2;  sumi2 += sum2[0]*ls1 + sum2[1]*ls2.
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "sumi_accumulate"));
    auto foldHalves = [&](emitc::VariableOp v0, emitc::VariableOp v1) {
      mlir::Value a =
          rewriter.create<emitc::LoadOp>(loc, i32Type, v0).getResult();
      mlir::Value b =
          rewriter.create<emitc::LoadOp>(loc, i32Type, v1).getResult();
      mlir::Value aScaled =
          rewriter.create<emitc::MulOp>(loc, i32Type, a, ls1I32).getResult();
      mlir::Value bScaled =
          rewriter.create<emitc::MulOp>(loc, i32Type, b, ls2I32).getResult();
      return rewriter
          .create<emitc::AddOp>(loc, i32Type, aScaled, bScaled)
          .getResult();
    };
    mlir::Value sumi1Add = foldHalves(sum1Var[0], sum1Var[1]);
    mlir::Value sumi1Cur =
        rewriter.create<emitc::LoadOp>(loc, i32Type, sumi1Var).getResult();
    rewriter.create<emitc::AssignOp>(
        loc, sumi1Var,
        rewriter.create<emitc::AddOp>(loc, i32Type, sumi1Cur, sumi1Add)
            .getResult());
    mlir::Value sumi2Add = foldHalves(sum2Var[0], sum2Var[1]);
    mlir::Value sumi2Cur =
        rewriter.create<emitc::LoadOp>(loc, i32Type, sumi2Var).getResult();
    rewriter.create<emitc::AssignOp>(
        loc, sumi2Var,
        rewriter.create<emitc::AddOp>(loc, i32Type, sumi2Cur, sumi2Add)
            .getResult());
  }

  // sumf = sumf + d * ((float)sumi1 + 0.125f * (float)sumi2);  -- ONE
  // emitc.expression (ggml's single C statement). The 0.125 (IQ1M_DELTA) is
  // applied EXACTLY ONCE here, to (float)sumi2 only; the inner add stays in the
  // expression tree. Invoked in STRICT ascending super-block order.
  rewriter.create<emitc::VerbatimOp>(
      loc, stepComment(opName, role, "fp32_accumulate_with_delta"));
  mlir::Value sumi1Final =
      rewriter.create<emitc::LoadOp>(loc, i32Type, sumi1Var).getResult();
  mlir::Value sumi2Final =
      rewriter.create<emitc::LoadOp>(loc, i32Type, sumi2Var).getResult();
  mlir::Value sumfCur =
      rewriter.create<emitc::LoadOp>(loc, floatType, sumfVar).getResult();
  mlir::Value deltaConst =
      rewriter.create<emitc::LiteralOp>(loc, floatType, "0.125f");
  auto accumExpr = rewriter.create<emitc::ExpressionOp>(
      loc, floatType, /*do_not_inline=*/false);
  {
    mlir::OpBuilder::InsertionGuard exprGuard(rewriter);
    mlir::Block *exprBlock = rewriter.createBlock(&accumExpr.getRegion());
    rewriter.setInsertionPointToStart(exprBlock);
    mlir::Value sumi1Float =
        rewriter.create<emitc::CastOp>(loc, floatType, sumi1Final)
            .getResult();
    mlir::Value sumi2Float =
        rewriter.create<emitc::CastOp>(loc, floatType, sumi2Final)
            .getResult();
    mlir::Value deltaScaled =
        rewriter.create<emitc::MulOp>(loc, floatType, deltaConst, sumi2Float)
            .getResult();
    mlir::Value inner =
        rewriter.create<emitc::AddOp>(loc, floatType, sumi1Float,
                                      deltaScaled)
            .getResult();
    mlir::Value blockTerm =
        rewriter.create<emitc::MulOp>(loc, floatType, d, inner).getResult();
    mlir::Value sumfNext =
        rewriter.create<emitc::AddOp>(loc, floatType, sumfCur, blockTerm)
            .getResult();
    rewriter.create<emitc::YieldOp>(loc, sumfNext);
  }
  rewriter.create<emitc::VerbatimOp>(
      loc, assignComment("sumf", opName, role));
  rewriter.create<emitc::AssignOp>(loc, sumfVar, accumExpr.getResult());
}


// NOTE: the monolith emitIQ1MQ8KBlockDot was RETIRED at the iq1_m flip (L3). The
// front door now constructs the typed super-block SCALAR-accumulator GRID loop body
// (fold_model "scalar_delta_grid", stride 56), lowered by
// emitTypedSuperBlockScalarDeltaGridLoopBodyIq1M, which reuses the SHARED byte-exact
// anchors above (emitIQ1MCanonicalGridTableDecl + emitIQ1MSuperBlockGridBody) -- the
// same anchors this retired monolith called, so the flip is byte-identical by
// construction (modulo the source-op provenance token + the func name).

// NOTE: the monolith emitTQ2_0Q8_KBlockDot was RETIRED at the tq2_0 flip (C_construct
// 24->25, the FIRST TQ-family member). The front door now constructs the typed super-block
// SCALAR-accumulator loop body (fold_model "scalar_delta_grid", stride 66) carrying the
// tq2_0 FUSED 2-bit TERNARY integer-core brick (GgmlBlockDotTQ20Q8KTernaryCoreOp), lowered
// by this emitTypedSuperBlockScalarDeltaGridLoopBodyTQ20 -- a byte-exact code-move of the
// retired monolith's per-super-block body, re-parameterized to source the per-super-block
// addresses from the ternary-core brick's operands (block_index tied to the loop induction
// variable). The emitted C is byte-identical to the retired monolith (same fused 2-bit
// plane ternary dot + single-scale scalar fp32 fold, same facts, same op order) modulo the
// source-op provenance token + the func name. Like iq2_xxs the brick carries the SAME Win-A
// integer_core_lmul m2/m1 gearbox (kernel key "tq2_0"), so the capability-keyed VLEN128 m2 /
// VLEN256 m1 selection is preserved on the constructed op.
mlir::LogicalResult
VariantToEmitCFunc::emitTypedSuperBlockScalarDeltaGridLoopBodyTQ20(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    weftrvv::WithVLOp scope, mlir::Value avlArg, mlir::Type sizeType,
    llvm::DenseMap<mlir::Value, mlir::Value> &valueMap,
    weftrvv::TypedSuperBlockBlockDotLoopBodyOp loopBody) const {
    (void)scope;
    // ---- Region walk (identify, no emit): the tq2_0 ternary-core brick + yield. ----
    weftrvv::GgmlBlockDotTQ20Q8KTernaryCoreOp coreOp;
    weftrvv::TypedSuperBlockBlockDotLoopYieldOp yieldOp;
    loopBody.getBody().walk([&](mlir::Operation *bodyOp) {
      if (auto o =
              llvm::dyn_cast<weftrvv::GgmlBlockDotTQ20Q8KTernaryCoreOp>(bodyOp))
        coreOp = o;
      else if (auto o =
                   llvm::dyn_cast<weftrvv::TypedSuperBlockBlockDotLoopYieldOp>(
                       bodyOp))
        yieldOp = o;
    });

    // ---- Region-driven gate (fail-closed, I7): the byte-exact SCALAR-accumulator
    // TERNARY body requires the tq2_0 ternary-core brick + the SINGLE scalar yield,
    // the (index, sumf scalar) entry-arg pair, and the brick's block_index tied to the
    // loop induction variable (region arg 0) -- the anti-bypass tie (the emit provably
    // tracks the region content, not merely the loop op attrs). ----
    mlir::Block &coreBlock = loopBody.getBody().front();
    if (!coreOp || !yieldOp)
      return rewriter.notifyMatchFailure(
          loopBody, "tq2_0 super-block scalar-accumulator ternary body requires "
                    "the tq2_0 fused 2-bit ternary integer-core brick + the single "
                    "scalar yield");
    if (coreBlock.getNumArguments() != 2)
      return rewriter.notifyMatchFailure(
          loopBody, "tq2_0 super-block scalar-accumulator ternary body region "
                    "must carry exactly the (super_block_index, sumf) pair");
    mlir::Value sbIndex = coreBlock.getArgument(0);
    mlir::Value sumfArg = coreBlock.getArgument(1);
    if (yieldOp.getSumsNext() != sumfArg || yieldOp.getSumfNext())
      return rewriter.notifyMatchFailure(
          yieldOp, "tq2_0 super-block scalar yield must carry the loop-carried "
                   "sumf scalar ALONE (no second operand under the scalar fold)");
    if (coreOp.getBlockIndex() != sbIndex)
      return rewriter.notifyMatchFailure(
          loopBody, "the tq2_0 super-block ternary-core brick's block_index must "
                    "be the loop induction variable (region arg 0) so the emit "
                    "addresses base + ib*stride, not super-block-0");

    mlir::Value weightBase = valueMap.lookup(loopBody.getWeightBase());
    mlir::Value activationBase = valueMap.lookup(loopBody.getActivationBase());
    mlir::Value output = valueMap.lookup(loopBody.getOutput());
    if (!weightBase || !activationBase || !output)
      return rewriter.notifyMatchFailure(
          loopBody, "tq2_0 super-block scalar-accumulator ternary ABI operand "
                    "unmapped");

    llvm::StringRef opName = loopBody.getWEFTEmitCLowerableSourceOpName();
    llvm::StringRef role = loopBody.getWEFTEmitCLowerableSourceRole();
    mlir::MLIRContext *ctx = rewriter.getContext();
    mlir::Type i32Type = emitc::OpaqueType::get(ctx, "int");
    mlir::Type floatType = emitc::OpaqueType::get(ctx, "float");
    mlir::Type weightPtrType = weightBase.getType();
    mlir::Type activationPtrType = activationBase.getType();

    // The block-format structural facts. The strides + qk come off the LOOP OP (the
    // byte-exact schedule shape knobs); the per-region byte offsets come off the tq2_0
    // ternary-core BRICK that owns them (I4 mirror).
    int64_t qk = loopBody.getQk();                                  // 256
    int64_t weightStride = loopBody.getWeightBlockStride();         // 66
    int64_t activationStride = loopBody.getActivationBlockStride(); // 292
    int64_t qsOffset = coreOp.getWeightQsByteOffset();              //  0
    int64_t weightDOffset = coreOp.getWeightDByteOffset();          // 64
    int64_t activationDOffset = coreOp.getActivationDByteOffset();  //  0
    int64_t q8Offset = coreOp.getActivationQuantByteOffset();       //  4
    int64_t planeLanes = 32; // the 32-element 2-bit plane (ggml's FUSED strip).
    int64_t planesPerChunk = 4; // the 4 2-bit shifts {0,2,4,6} per qs chunk.
    int64_t chunkBytes = 32;    // a qs chunk is 32 packed bytes (= 128 weights).
    int64_t numChunks = qk / 128; // 2 chunks of 128 weights at QK_K=256.

    // The 2-bit ternary dot runs ONE FUSED 32-lane plane body per shift (ggml's
    // shipped _vl128/_vl256 lane structure): the 32-byte qs chunk loads ONCE at
    // the whole-LMUL anchor, then the 4 2-bit planes each unpack 32 ternary lanes
    // (vand/vsrl + vsub -1) and vwmacc DIRECTLY against their matching 32 q8 lanes
    // into a wide i16 accumulator -- NO aux8[256] scratch round-trip, NO 16x
    // 16-lane reductions, ONE vwredsum (i16->i32m1) per 32-byte chunk. The anchor's
    // i8 strip VLMAX must span the 32-element plane: m2 at VLEN128 (e8m1 VLMAX 16 <
    // 32), the lighter m1 at VLEN256 (e8m1 VLMAX reaches 32). The gearbox stamps
    // integer_core_lmul from getRVVStripVLMAXElements (single truth source); the
    // The i16 accumulator is 2*core (m4 at m2, m2 at m1); the
    // i16 vacc never overflows: |ternary|<=2, |q8|<=127, 4 planes -> max |acc| <=
    // 4*2*127 = 1016 << 32767.
    if (!coreOp.getIntegerCoreLmul())
      return rewriter.notifyMatchFailure(
          coreOp, "tq2_0 core reached emission without final integer_core_lmul");
    llvm::StringRef coreLmul = *coreOp.getIntegerCoreLmul();
    llvm::StringRef wideLmul = (coreLmul == "m2") ? "m4" : "m2";
    mlir::Type u8CoreType =
        emitc::OpaqueType::get(ctx, ("vuint8" + coreLmul + "_t").str());
    mlir::Type i8CoreType =
        emitc::OpaqueType::get(ctx, ("vint8" + coreLmul + "_t").str());
    mlir::Type i16WideType =
        emitc::OpaqueType::get(ctx, ("vint16" + wideLmul + "_t").str());
    mlir::Type i32m1Type = emitc::OpaqueType::get(ctx, "vint32m1_t");
    mlir::Type i32ImmType = emitc::OpaqueType::get(ctx, "int");
    mlir::Type i8PtrType =
        emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int8_t"));
    mlir::Type u8PtrType =
        emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const uint8_t"));
    llvm::StringRef fp16ReadCallee = "(float)*(const _Float16 *)";

    auto sizeLit = [&](int64_t v) { return emitSizeLit(rewriter, loc, sizeType, v); };
    auto byteOffsetPtr = [&](mlir::Value base, mlir::Type ptrType, int64_t fixed,
                             mlir::Type castType) -> mlir::Value {
      mlir::Value full = base;
      if (fixed != 0)
        full = rewriter.create<emitc::AddOp>(loc, ptrType, base, sizeLit(fixed));
      return rewriter.create<emitc::CastOp>(loc, castType, full).getResult();
    };

    rewriter.create<emitc::VerbatimOp>(loc, routeSourceComment(opName, role));

    // size_t nb = n / QK_K;
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "super_block_count"));
    mlir::Value nb =
        rewriter.create<emitc::DivOp>(loc, sizeType, avlArg, sizeLit(qk));

    // float sumf = 0.0f;  -- the carried SCALAR fp32 accumulator the per-super-
    // block fold lands in IN-LOOP (in super-block order); declared + zeroed ONCE
    // OUTSIDE the loop (mirrors _generic's `float sumf = 0.0f;`).
    rewriter.create<emitc::VerbatimOp>(
        loc, localVariableComment("sumf", opName, role));
    auto sumfVar = rewriter.create<emitc::VariableOp>(
        loc, emitc::LValueType::get(floatType), emitc::OpaqueAttr::get(ctx, ""));
    mlir::Value sumfZero =
        rewriter.create<emitc::LiteralOp>(loc, floatType, "0.0f");
    rewriter.create<emitc::AssignOp>(loc, sumfVar, sumfZero);

    // The outer super-block loop: for (size_t ib = 0; ib < nb; ib += 1).
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "super_block_loop"));
    auto blockLoop = rewriter.create<emitc::ForOp>(loc, sizeLit(0), nb,
                                                   sizeLit(1),
                                                   /*bodyBuilder=*/nullptr);
    {
      mlir::OpBuilder::InsertionGuard guard(rewriter);
      rewriter.setInsertionPointToStart(blockLoop.getBody());
      mlir::Value ib = blockLoop.getInductionVar();

      // W-E: per-super-block base = base + ib*stride, built from the ternary-core
      // brick's (base operand, block_index operand) through a per-iteration memo.
      // Correct wiring collapses to exactly TWO emitted bases -- xb (super_block_base_x)
      // and yb (super_block_base_y) -- byte-identical to the monolith's per-block base
      // arithmetic (MulOp(ib, stride) + AddOp(base, off)). A CHANGED brick base operand
      // keys a DIFFERENT memo entry (anti-bypass, operand-driven emit).
      llvm::DenseMap<std::pair<mlir::Value, mlir::Value>, mlir::Value>
          blockBaseMemo;
      auto blockBaseFor = [&](mlir::Value bufferSSA, mlir::Value blockIndexSSA,
                              int64_t stride, const char *step) -> mlir::Value {
        std::pair<mlir::Value, mlir::Value> key(bufferSSA, blockIndexSSA);
        auto it = blockBaseMemo.find(key);
        if (it != blockBaseMemo.end())
          return it->second;
        mlir::Value emittedBase = valueMap.lookup(bufferSSA);
        rewriter.create<emitc::VerbatimOp>(loc, stepComment(opName, role, step));
        mlir::Value off =
            rewriter.create<emitc::MulOp>(loc, sizeType, ib, sizeLit(stride));
        mlir::Value base = rewriter.create<emitc::AddOp>(
            loc, emittedBase.getType(), emittedBase, off);
        blockBaseMemo[key] = base;
        return base;
      };

      mlir::Value xb =
          blockBaseFor(coreOp.getWeightBase(), coreOp.getBlockIndex(),
                       weightStride, "super_block_base_x");
      mlir::Value yb =
          blockBaseFor(coreOp.getActivationBase(), coreOp.getBlockIndex(),
                       activationStride, "super_block_base_y");

      // The q8 quant base (vy + activation_quant_byte_offset).
      mlir::Value q8Base =
          byteOffsetPtr(yb, activationPtrType, q8Offset, i8PtrType);

      // ---- (A+B FUSED) the SINGLE per-super-block integer accumulator ----
      // int sumi = 0;  (the per-super-block ternary*q8 dot; integer add is
      // order-free so the per-chunk partial sums fold into one scalar).
      rewriter.create<emitc::VerbatimOp>(
          loc, localVariableComment("sumi", opName, role));
      auto sumiVar = rewriter.create<emitc::VariableOp>(
          loc, emitc::LValueType::get(i32Type), emitc::OpaqueAttr::get(ctx, ""));
      rewriter.create<emitc::AssignOp>(
          loc, sumiVar,
          rewriter.create<emitc::LiteralOp>(loc, i32Type, "0").getResult());

      // ggml's FUSED dot over the WHOLE super-block. The wide i16 plane accumulator
      // is zeroed ONCE (NOT per chunk); BOTH 32-byte qs chunks then vwmacc into the
      // SAME accumulator, and ONE vwredsum (i16->i32m1) folds the whole super-block.
      // Integer add is order-free, so a single 32-lane accumulator carried across
      // both chunks then reduced is byte-identical to the per-chunk partial sums:
      //   vacc16[l] = Σ_{chunk,j} (ternary(chunk,j)[l] * q8[chunk*128 + j*32 + l]),
      // and vwredsum(Σ over lanes) = reduce(chunk0) + reduce(chunk1) = the same sumi.
      // REGISTER-PRESSURE FIX (byte-exact, LMUL UNCHANGED): the retired per-chunk
      // form left THREE live i16<wide> groups the -O3 scheduler overlaps -- the two
      // per-chunk accumulators + the CSE-hoisted zero-seed -- which at VLEN128 (m4,
      // 4 vregs each = 12/32) forced the q8 e8m2 strips to spill (vs2r.v/vl2r.v round
      // trips). Fusing to ONE accumulator collapses those 3 groups to 1, so the strips
      // stay in the regfile and the whole-reg spills vanish. The element pairing +
      // every intrinsic/width is unchanged. |vacc16| <= 8 planes * 2 * 127 = 2032 <<
      // 32767, so the i16 accumulator still never overflows across both chunks.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "chunk_dot"));
      std::string accSetvl = ("__riscv_vsetvl_e16" + wideLmul).str();
      mlir::Value vlAcc = emitOpaqueCallBuilt(
          rewriter, loc, sizeType, accSetvl, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {sizeLit(planeLanes)};
          });
      std::string accInitCallee = ("__riscv_vmv_v_x_i16" + wideLmul).str();
      mlir::Value vacc16 = emitOpaqueCallBuilt(
          rewriter, loc, i16WideType, accInitCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            mlir::Value accZero =
                rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "0");
            return {accZero, vlAcc};
          });

      for (int64_t chunk = 0; chunk < numChunks; ++chunk) {
        int64_t qsChunk = chunk * chunkBytes; // qs advances 32 bytes per chunk.
        // size_t vl = vsetvl_e8<core>(32);  (the 32-lane plane strip).
        std::string planeSetvl =
            ("__riscv_vsetvl_e8" + coreLmul).str();
        mlir::Value vl = emitOpaqueCallBuilt(
            rewriter, loc, sizeType, planeSetvl, opName, role,
            [&](mlir::OpBuilder &b,
                mlir::Location l) -> llvm::SmallVector<mlir::Value> {
              return {sizeLit(planeLanes)};
            });

        // vuint8<core> q2 = vle8(qs + chunk*32);  (load the 32 packed bytes ONCE).
        mlir::Value qsPtr =
            byteOffsetPtr(xb, weightPtrType, qsOffset + qsChunk, u8PtrType);
        std::string qsLoadCallee = ("__riscv_vle8_v_u8" + coreLmul).str();
        mlir::Value q2 =
            emitOpaqueCall(rewriter, loc, u8CoreType, qsLoadCallee,
                           mlir::ValueRange{qsPtr, vl}, opName, role);

        for (int64_t j = 0; j < planesPerChunk; ++j) {
          int64_t shift = 2 * j;
          // u8<core> nib = (shift ? vsrl(q2, shift) : q2); t = vand(nib, 3).
          mlir::Value nib = q2;
          if (shift != 0) {
            std::string srlCallee = ("__riscv_vsrl_vx_u8" + coreLmul).str();
            nib = emitOpaqueCallBuilt(
                rewriter, loc, u8CoreType, srlCallee, opName, role,
                [&](mlir::OpBuilder &b,
                    mlir::Location l) -> llvm::SmallVector<mlir::Value> {
                  mlir::Value amt = rewriter.create<emitc::LiteralOp>(
                      loc, i32ImmType, std::to_string(shift));
                  return {q2, amt, vl};
                });
          }
          std::string andCallee = ("__riscv_vand_vx_u8" + coreLmul).str();
          mlir::Value q2bits = emitOpaqueCallBuilt(
              rewriter, loc, u8CoreType, andCallee, opName, role,
              [&](mlir::OpBuilder &b,
                  mlir::Location l) -> llvm::SmallVector<mlir::Value> {
                mlir::Value mask3 =
                    rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "0x03");
                return {nib, mask3, vl};
              });
          // i8<core> q2i = vreinterpret(t); vq = vsub(q2i, 1)  (the ternary -1
          // bias in the i8 domain; q2 in [0,3] so the subtract is exact).
          std::string reCallee =
              ("__riscv_vreinterpret_v_u8" + coreLmul + "_i8" + coreLmul).str();
          mlir::Value q2i =
              emitOpaqueCall(rewriter, loc, i8CoreType, reCallee,
                             mlir::ValueRange{q2bits}, opName, role);
          std::string biasCallee = ("__riscv_vsub_vx_i8" + coreLmul).str();
          mlir::Value vq = emitOpaqueCallBuilt(
              rewriter, loc, i8CoreType, biasCallee, opName, role,
              [&](mlir::OpBuilder &b,
                  mlir::Location l) -> llvm::SmallVector<mlir::Value> {
                mlir::Value biasImm =
                    rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "1");
                return {q2i, biasImm, vl};
              });
          // i8<core> vy = vle8(q8 + chunk*128 + j*32);  (the matching 32 q8).
          int64_t q8PlaneOffset = chunk * 128 + j * 32;
          mlir::Value q8Ptr =
              rewriter
                  .create<emitc::AddOp>(loc, i8PtrType, q8Base,
                                        sizeLit(q8PlaneOffset))
                  .getResult();
          std::string q8LoadCallee = ("__riscv_vle8_v_i8" + coreLmul).str();
          mlir::Value vy =
              emitOpaqueCall(rewriter, loc, i8CoreType, q8LoadCallee,
                             mlir::ValueRange{q8Ptr, vl}, opName, role);
          // vacc16 = vwmacc(vacc16, vq, vy);  (widening i8*i8 -> i16 accumulate;
          // |vq|<=2, |vy|<=127, 4 planes -> |vacc16| <= 1016 << 32767).
          std::string maccCallee = ("__riscv_vwmacc_vv_i16" + wideLmul).str();
          vacc16 = emitOpaqueCall(rewriter, loc, i16WideType, maccCallee,
                                  mlir::ValueRange{vacc16, vq, vy, vl}, opName,
                                  role);
        }
      }

      // sumi += vmv_x_s(vwredsum_i16<wide>_i32m1(vacc16, 0, 32));  (ONE wide reduce
      // of the WHOLE super-block's merged i16 accumulator; integer / order-free, so
      // the single reduce equals reduce(chunk0) + reduce(chunk1)).
      mlir::Value vlRed = emitOpaqueCallBuilt(
          rewriter, loc, sizeType, accSetvl, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            return {sizeLit(planeLanes)};
          });
      std::string seedCallee = "__riscv_vmv_v_x_i32m1";
      mlir::Value seed = emitOpaqueCallBuilt(
          rewriter, loc, i32m1Type, seedCallee, opName, role,
          [&](mlir::OpBuilder &b,
              mlir::Location l) -> llvm::SmallVector<mlir::Value> {
            mlir::Value zeroImm =
                rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "0");
            return {zeroImm, sizeLit(1)};
          });
      std::string reduceCallee =
          ("__riscv_vwredsum_vs_i16" + wideLmul + "_i32m1").str();
      mlir::Value red =
          emitOpaqueCall(rewriter, loc, i32m1Type, reduceCallee,
                         mlir::ValueRange{vacc16, seed, vlRed}, opName, role);
      std::string extractCallee = "__riscv_vmv_x_s_i32m1_i32";
      mlir::Value isuml =
          emitOpaqueCall(rewriter, loc, i32Type, extractCallee,
                         mlir::ValueRange{red}, opName, role);

      // sumi += isuml;  (integer, order-free; a SINGLE per-super-block reduce).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "sumi_accumulate"));
      mlir::Value sumiCur =
          rewriter.create<emitc::LoadOp>(loc, i32Type, sumiVar).getResult();
      mlir::Value sumiNext =
          rewriter.create<emitc::AddOp>(loc, i32Type, sumiCur, isuml)
              .getResult();
      rewriter.create<emitc::AssignOp>(loc, sumiVar, sumiNext);

      // ---- (C) the SINGLE-SCALE SCALAR fp32 fold: sumf += (float)sumi * d ----
      // float dy = *(const float *)(yb + 0);  -- the fp32 q8_K activation scale.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "fold_activation_d"));
      mlir::Value dyAddr = yb;
      if (activationDOffset != 0)
        dyAddr = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                               sizeLit(activationDOffset));
      mlir::Type constFloatPtrType =
          emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const float"));
      mlir::Value dyPtr =
          rewriter.create<emitc::CastOp>(loc, constFloatPtrType, dyAddr)
              .getResult();
      mlir::Value dyIndex0 =
          rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
      mlir::Value dyElem =
          rewriter
              .create<emitc::SubscriptOp>(
                  loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(dyPtr),
                  dyIndex0)
              .getResult();
      mlir::Type constFloatType = emitc::OpaqueType::get(ctx, "const float");
      mlir::Value dy =
          rewriter.create<emitc::LoadOp>(loc, constFloatType, dyElem)
              .getResult();

      // float dx = (float)*(const _Float16 *)(xb + 64);  -- the fp16 tq2_0
      // super-block scale (at the END of block_tq2_0).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "fold_scale_d"));
      mlir::Value dxAddr = xb;
      if (weightDOffset != 0)
        dxAddr = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                               sizeLit(weightDOffset));
      mlir::Value dx = emitOpaqueCall(rewriter, loc, floatType, fp16ReadCallee,
                                      mlir::ValueRange{dxAddr}, opName, role,
                                      llvm::StringRef("fcvt.s.h"));
      // float d = dy * dx;  -- the single super-block scale, its OWN product
      // (mirrors _generic's `const float d = y[i].d * fp16(x[i].d);`).
      mlir::Value d =
          rewriter.create<emitc::MulOp>(loc, floatType, dy, dx).getResult();

      // sumf = sumf + (float)sumi * d;  -- ONE emitc.expression so the cast +
      // the product + the add render as ggml's single C statement (quants.c:508
      // `sumf += (float) sumi * d`) and track its contraction.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "scalar_fold"));
      mlir::Value sumiFinal =
          rewriter.create<emitc::LoadOp>(loc, i32Type, sumiVar).getResult();
      mlir::Value sumfCur =
          rewriter.create<emitc::LoadOp>(loc, floatType, sumfVar).getResult();
      auto foldExpr = rewriter.create<emitc::ExpressionOp>(
          loc, floatType, /*do_not_inline=*/false);
      {
        mlir::OpBuilder::InsertionGuard exprGuard(rewriter);
        mlir::Block *exprBlock = rewriter.createBlock(&foldExpr.getRegion());
        rewriter.setInsertionPointToStart(exprBlock);
        // (float)sumi  -- the int->float conversion.
        mlir::Value sumiFloat =
            rewriter.create<emitc::CastOp>(loc, floatType, sumiFinal)
                .getResult();
        // (float)sumi * d  -- the super-block term.
        mlir::Value term =
            rewriter.create<emitc::MulOp>(loc, floatType, sumiFloat, d);
        // sumf + (float)sumi * d  -- the `+=`.
        mlir::Value sumfNext =
            rewriter.create<emitc::AddOp>(loc, floatType, sumfCur, term);
        rewriter.create<emitc::YieldOp>(loc, sumfNext);
      }
      rewriter.create<emitc::VerbatimOp>(
          loc, assignComment("sumf", opName, role));
      rewriter.create<emitc::AssignOp>(loc, sumfVar, foldExpr.getResult());
    }

    // *s = sumf;  (structured scalar store through the float * output pointer).
    // The LoadOp of the carried sumf is emitted BEFORE the output subscript, exactly
    // as the retired monolith emitted it, so the emit is byte-identical.
    mlir::Value sumf =
        rewriter.create<emitc::LoadOp>(loc, floatType, sumfVar).getResult();
    auto outPointer =
        llvm::dyn_cast<mlir::TypedValue<emitc::PointerType>>(output);
    if (!outPointer)
      return rewriter.notifyMatchFailure(
          loopBody, "tq2_0 super-block scalar-accumulator ternary output not a "
                    "pointer");
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "store_s"));
    mlir::Value outIndex =
        rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
    emitc::SubscriptOp outSubscript =
        rewriter.create<emitc::SubscriptOp>(loc, outPointer, outIndex);
    rewriter.create<emitc::AssignOp>(loc, outSubscript.getResult(), sumf);

    return mlir::success();
  }

// NOTE: the monolith emitTQ1_0Q8_KBlockDot was RETIRED at the tq1_0 flip (C_construct
// 25->26, the SECOND TQ-family member). The front door now constructs the typed super-block
// SCALAR-accumulator loop body (fold_model "scalar_delta_grid", stride 54) carrying the
// tq1_0 BASE-3 TERNARY integer-core brick (GgmlBlockDotTQ10Q8KTernaryCoreOp), lowered by this
// emitTypedSuperBlockScalarDeltaGridLoopBodyTQ10 -- a byte-exact code-move of the retired
// monolith's per-super-block body, re-parameterized to source the per-super-block addresses
// from the ternary-core brick's operands (block_index tied to the loop induction variable).
// The emitted C is byte-identical to the retired monolith (same base-3 trit unpack + flat-256
// integer dot + single-scale scalar fp32 fold, same facts, same op order) modulo the
// source-op provenance token + the func name. Like tq2_0 the brick carries the SAME Win-A
// fixed VLEN-universal body and therefore carries no emitter-inert LMUL schedule field. It REUSES the whole tq2_0 ternary
// scaffold at C2 marginal cost and differs ONLY in the base-3 unpack (section A).
mlir::LogicalResult
VariantToEmitCFunc::emitTypedSuperBlockScalarDeltaGridLoopBodyTQ10(
    mlir::ConversionPatternRewriter &rewriter, mlir::Location loc,
    weftrvv::WithVLOp scope, mlir::Value avlArg, mlir::Type sizeType,
    llvm::DenseMap<mlir::Value, mlir::Value> &valueMap,
    weftrvv::TypedSuperBlockBlockDotLoopBodyOp loopBody) const {
    (void)scope;
    // ---- Region walk (identify, no emit): the tq1_0 ternary-core brick + yield. ----
    weftrvv::GgmlBlockDotTQ10Q8KTernaryCoreOp coreOp;
    weftrvv::TypedSuperBlockBlockDotLoopYieldOp yieldOp;
    loopBody.getBody().walk([&](mlir::Operation *bodyOp) {
      if (auto o =
              llvm::dyn_cast<weftrvv::GgmlBlockDotTQ10Q8KTernaryCoreOp>(bodyOp))
        coreOp = o;
      else if (auto o =
                   llvm::dyn_cast<weftrvv::TypedSuperBlockBlockDotLoopYieldOp>(
                       bodyOp))
        yieldOp = o;
    });

    // ---- Region-driven gate (fail-closed, I7): the byte-exact SCALAR-accumulator
    // BASE-3 TERNARY body requires the tq1_0 ternary-core brick + the SINGLE scalar
    // yield, the (index, sumf scalar) entry-arg pair, and the brick's block_index tied
    // to the loop induction variable (region arg 0) -- the anti-bypass tie (the emit
    // provably tracks the region content, not merely the loop op attrs). ----
    mlir::Block &coreBlock = loopBody.getBody().front();
    if (!coreOp || !yieldOp)
      return rewriter.notifyMatchFailure(
          loopBody, "tq1_0 super-block scalar-accumulator ternary body requires "
                    "the tq1_0 base-3 ternary integer-core brick + the single "
                    "scalar yield");
    if (coreBlock.getNumArguments() != 2)
      return rewriter.notifyMatchFailure(
          loopBody, "tq1_0 super-block scalar-accumulator ternary body region "
                    "must carry exactly the (super_block_index, sumf) pair");
    mlir::Value sbIndex = coreBlock.getArgument(0);
    mlir::Value sumfArg = coreBlock.getArgument(1);
    if (yieldOp.getSumsNext() != sumfArg || yieldOp.getSumfNext())
      return rewriter.notifyMatchFailure(
          yieldOp, "tq1_0 super-block scalar yield must carry the loop-carried "
                   "sumf scalar ALONE (no second operand under the scalar fold)");
    if (coreOp.getBlockIndex() != sbIndex)
      return rewriter.notifyMatchFailure(
          loopBody, "the tq1_0 super-block ternary-core brick's block_index must "
                    "be the loop induction variable (region arg 0) so the emit "
                    "addresses base + ib*stride, not super-block-0");

    mlir::Value weightBase = valueMap.lookup(loopBody.getWeightBase());
    mlir::Value activationBase = valueMap.lookup(loopBody.getActivationBase());
    mlir::Value output = valueMap.lookup(loopBody.getOutput());
    if (!weightBase || !activationBase || !output)
      return rewriter.notifyMatchFailure(
          loopBody, "tq1_0 super-block scalar-accumulator ternary ABI operand "
                    "unmapped");

    llvm::StringRef opName = loopBody.getWEFTEmitCLowerableSourceOpName();
    llvm::StringRef role = loopBody.getWEFTEmitCLowerableSourceRole();
    mlir::MLIRContext *ctx = rewriter.getContext();
    mlir::Type i32Type = emitc::OpaqueType::get(ctx, "int");
    mlir::Type floatType = emitc::OpaqueType::get(ctx, "float");
    mlir::Type weightPtrType = weightBase.getType();
    mlir::Type activationPtrType = activationBase.getType();

    // The block-format structural facts. The strides + qk come off the LOOP OP (the
    // byte-exact schedule shape knobs); the per-region byte offsets come off the tq1_0
    // base-3 ternary-core BRICK that owns them (I4 mirror).
    int64_t qk = loopBody.getQk();                                  // 256
    int64_t weightStride = loopBody.getWeightBlockStride();         // 54
    int64_t activationStride = loopBody.getActivationBlockStride(); // 292
    int64_t qsOffset = coreOp.getWeightQsByteOffset();              //  0
    int64_t qhOffset = coreOp.getWeightQhByteOffset();              // 48
    int64_t weightDOffset = coreOp.getWeightDByteOffset();          // 52
    int64_t activationDOffset = coreOp.getActivationDByteOffset();  //  0
    int64_t q8Offset = coreOp.getActivationQuantByteOffset();       //  4

    // ---- FUSED tq1_0 vec_dot leaf (P1 owned VLEN-universal structure) ----
    // The deployed integer core is the P1-proven owned leaf: a SINGLE i16m4
    // accumulator (vacc) fed by base-3 trit unpack + q8 pre-widened to i16 via
    // vmul_vv (init) / vmacc_vv (accumulate) chains, then ONE vwredsum over a FIXED
    // vl -- NO aux8[256] scratch store/reload, NO 8x serial per-super-block
    // vwredsum. Every region accumulates into vacc at a FIXED vl (32 main / 16 tail
    // + qh) so e16m4 VLMAX >= vl at any VLEN >= 128, and the final reduce over
    // exactly 32 active lanes bounds the sum regardless of VLMAX -- VLEN-universal:
    // byte-exact on rvv VLEN128 AND k1 VLEN256 with ONE core (the ggml hand-tuned
    // _vl128/_vl256 need two VLEN specializations; the single accumulator sidesteps
    // the VLEN128-only vget-split fold). Integer accumulation is order-free so the
    // fused order is byte-exact to _generic (i16 lanes bound <= 11*127 = 1397 <<
    // 32767, no overflow). PURE C-intrinsic (NO inline-asm, NO pinned schedule).

    // ggml's base-3 powers: pow3[l] = 3^l for l in 0..4 (qs) and 0..3 (qh).
    const int64_t pow3[6] = {1, 3, 9, 27, 81, 243};

    // The vector types: the base-3 unpack loads weight bytes as e8m2 and widens the
    // `*3` high-digit numerator to u16m4; q8 is pre-widened i8m2 -> i16m4 (vwcvt).
    // The single accumulator + the widened q8 + the ternary lane all live at i16m4;
    // the qh single-pass broadcast replicates the 4 qh bytes via u32m2 (4 u32 lanes
    // = 16 bytes = qh x4); the final reduce lands in i32m1.
    mlir::Type u8m2Type = emitc::OpaqueType::get(ctx, "vuint8m2_t");
    mlir::Type u16m4Type = emitc::OpaqueType::get(ctx, "vuint16m4_t");
    mlir::Type i8m2Type = emitc::OpaqueType::get(ctx, "vint8m2_t");
    mlir::Type i16m4Type = emitc::OpaqueType::get(ctx, "vint16m4_t");
    mlir::Type u32m2Type = emitc::OpaqueType::get(ctx, "vuint32m2_t");
    mlir::Type i32m1Type = emitc::OpaqueType::get(ctx, "vint32m1_t");
    mlir::Type i32ImmType = emitc::OpaqueType::get(ctx, "int");
    mlir::Type uintType = emitc::OpaqueType::get(ctx, "uint32_t");
    mlir::Type constU8Type = emitc::OpaqueType::get(ctx, "const uint8_t");
    mlir::Type i8PtrType =
        emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const int8_t"));
    mlir::Type u8PtrType =
        emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const uint8_t"));
    llvm::StringRef fp16ReadCallee = "(float)*(const _Float16 *)";

    auto sizeLit = [&](int64_t v) { return emitSizeLit(rewriter, loc, sizeType, v); };
    auto byteOffsetPtr = [&](mlir::Value base, mlir::Type ptrType, int64_t fixed,
                             mlir::Type castType) -> mlir::Value {
      mlir::Value full = base;
      if (fixed != 0)
        full = rewriter.create<emitc::AddOp>(loc, ptrType, base, sizeLit(fixed));
      return rewriter.create<emitc::CastOp>(loc, castType, full).getResult();
    };

    rewriter.create<emitc::VerbatimOp>(loc, routeSourceComment(opName, role));

    // size_t nb = n / QK_K;
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "super_block_count"));
    mlir::Value nb =
        rewriter.create<emitc::DivOp>(loc, sizeType, avlArg, sizeLit(qk));

    // static const uint8_t weft_tq1_0_pow16[16] = {1,1,1,1,3,3,3,3,9,9,9,9,27,27,27,27};
    // The qh SINGLE-pass base-3 plane weights: lane j of the 4x-replicated qh bytes
    // multiplies by 3^(j/4) (pow3[l] broadcast 4-wide). Declared ONCE at function
    // scope, broadcast-loaded via vle8 inside the loop (register reused per
    // super-block). Replaces the 4-pass per-plane aux8 stores of the retired form.
    {
      std::string decl =
          "static const uint8_t weft_tq1_0_pow16[16] = {1, 1, 1, 1, 3, 3, 3, "
          "3, 9, 9, 9, 9, 27, 27, 27, 27};";
      rewriter.create<emitc::VerbatimOp>(loc, decl);
    }

    // float sumf = 0.0f;  -- the carried SCALAR fp32 accumulator the per-super-
    // block fold lands in IN-LOOP (in super-block order); declared + zeroed ONCE
    // OUTSIDE the loop (mirrors _generic's `float sumf = 0.0f;`).
    rewriter.create<emitc::VerbatimOp>(
        loc, localVariableComment("sumf", opName, role));
    auto sumfVar = rewriter.create<emitc::VariableOp>(
        loc, emitc::LValueType::get(floatType), emitc::OpaqueAttr::get(ctx, ""));
    mlir::Value sumfZero =
        rewriter.create<emitc::LiteralOp>(loc, floatType, "0.0f");
    rewriter.create<emitc::AssignOp>(loc, sumfVar, sumfZero);

    // The outer super-block loop: for (size_t ib = 0; ib < nb; ib += 1).
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "super_block_loop"));
    auto blockLoop = rewriter.create<emitc::ForOp>(loc, sizeLit(0), nb,
                                                   sizeLit(1),
                                                   /*bodyBuilder=*/nullptr);
    {
      mlir::OpBuilder::InsertionGuard guard(rewriter);
      rewriter.setInsertionPointToStart(blockLoop.getBody());
      mlir::Value ib = blockLoop.getInductionVar();

      // W-E: per-super-block base = base + ib*stride, built from the ternary-core
      // brick's (base operand, block_index operand) through a per-iteration memo.
      // Correct wiring collapses to exactly TWO emitted bases -- xb (super_block_base_x)
      // and yb (super_block_base_y) -- byte-identical to the monolith's per-block base
      // arithmetic (MulOp(ib, stride) + AddOp(base, off)). A CHANGED brick base operand
      // keys a DIFFERENT memo entry (anti-bypass, operand-driven emit).
      llvm::DenseMap<std::pair<mlir::Value, mlir::Value>, mlir::Value>
          blockBaseMemo;
      auto blockBaseFor = [&](mlir::Value bufferSSA, mlir::Value blockIndexSSA,
                              int64_t stride, const char *step) -> mlir::Value {
        std::pair<mlir::Value, mlir::Value> key(bufferSSA, blockIndexSSA);
        auto it = blockBaseMemo.find(key);
        if (it != blockBaseMemo.end())
          return it->second;
        mlir::Value emittedBase = valueMap.lookup(bufferSSA);
        rewriter.create<emitc::VerbatimOp>(loc, stepComment(opName, role, step));
        mlir::Value off =
            rewriter.create<emitc::MulOp>(loc, sizeType, ib, sizeLit(stride));
        mlir::Value base = rewriter.create<emitc::AddOp>(
            loc, emittedBase.getType(), emittedBase, off);
        blockBaseMemo[key] = base;
        return base;
      };

      mlir::Value xb =
          blockBaseFor(coreOp.getWeightBase(), coreOp.getBlockIndex(),
                       weightStride, "super_block_base_x");
      mlir::Value yb =
          blockBaseFor(coreOp.getActivationBase(), coreOp.getBlockIndex(),
                       activationStride, "super_block_base_y");

      // ---- FUSED base-3 ternary vec_dot (the P1 owned VLEN-universal leaf) ----
      // A SINGLE i16m4 accumulator `vacc` collects the WHOLE super-block ternary
      // dot: each region accumulates at a FIXED vl (32 main / 16 tail + qh) via
      // vmul_vv (init) / vmacc_vv, then ONE vwredsum over exactly 32 active lanes
      // folds it to sumi. NO aux8[256] scratch store/reload, NO 8x serial
      // per-strip vwredsum chain. Byte-exact (order-free integer sum) to the
      // retired aux8 form.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "fused_ternary_dot"));

      // q8 quant base = yb + q8_byte_offset, as const int8_t*.
      mlir::Value q8Base =
          byteOffsetPtr(yb, activationPtrType, q8Offset, i8PtrType);

      // tritDecode: a u8m2 weight-byte vector -> i16m4 ternary lane {-1,0,1}.
      //   (uint16_t)byte * 3 (vwmulu, high base-3 digit numerator) -> >> 8 (vsrl,
      //   xi in {0,1,2}) -> (u16 - 1) (vsub) -> reinterpret u16 -> i16 (the
      //   {-1,0,1} bias kept in i16, NO narrow). Order-free, byte-exact to
      //   `xi - 1`; the wide i16 lane never overflows.
      auto tritDecode = [&](mlir::Value tqx, int64_t lanes) -> mlir::Value {
        mlir::Value w = emitOpaqueCallBuilt(
            rewriter, loc, u16m4Type, "__riscv_vwmulu_vx_u16m4", opName, role,
            [&](mlir::OpBuilder &,
                mlir::Location) -> llvm::SmallVector<mlir::Value> {
              mlir::Value three =
                  rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "3");
              return {tqx, three, sizeLit(lanes)};
            });
        mlir::Value xi = emitOpaqueCallBuilt(
            rewriter, loc, u16m4Type, "__riscv_vsrl_vx_u16m4", opName, role,
            [&](mlir::OpBuilder &,
                mlir::Location) -> llvm::SmallVector<mlir::Value> {
              mlir::Value eight =
                  rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "8");
              return {w, eight, sizeLit(lanes)};
            });
        mlir::Value sub = emitOpaqueCallBuilt(
            rewriter, loc, u16m4Type, "__riscv_vsub_vx_u16m4", opName, role,
            [&](mlir::OpBuilder &,
                mlir::Location) -> llvm::SmallVector<mlir::Value> {
              mlir::Value one =
                  rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "1");
              return {xi, one, sizeLit(lanes)};
            });
        return emitOpaqueCall(rewriter, loc, i16m4Type,
                              "__riscv_vreinterpret_v_u16m4_i16m4",
                              mlir::ValueRange{sub}, opName, role);
      };
      // tritDigit: base-3 digit `l` of a loaded weight-byte vector. Digit 0 skips
      // the *pow3[0]==1 multiply (the P1 lean); digits 1..4 wrap via vmul.vx u8
      // (the mandatory mod-256 wrap IS the decode).
      auto tritDigit = [&](mlir::Value tqb, int64_t l,
                           int64_t lanes) -> mlir::Value {
        mlir::Value tqx = tqb;
        if (l != 0)
          tqx = emitOpaqueCallBuilt(
              rewriter, loc, u8m2Type, "__riscv_vmul_vx_u8m2", opName, role,
              [&](mlir::OpBuilder &,
                  mlir::Location) -> llvm::SmallVector<mlir::Value> {
                mlir::Value pow3Imm = rewriter.create<emitc::LiteralOp>(
                    loc, i32ImmType, std::to_string(pow3[l]));
                return {tqb, pow3Imm, sizeLit(lanes)};
              });
        return tritDecode(tqx, lanes);
      };
      // q8Wide: widen `lanes` q8 bytes at q8Base + off into i16m4 (vwcvt i8->i16),
      // pre-widened so it pairs directly with the i16 ternary lane in vmul/vmacc.
      auto q8Wide = [&](int64_t off, int64_t lanes) -> mlir::Value {
        mlir::Value ptr = q8Base;
        if (off != 0)
          ptr = rewriter
                    .create<emitc::AddOp>(loc, i8PtrType, q8Base, sizeLit(off))
                    .getResult();
        mlir::Value q8i8 =
            emitOpaqueCall(rewriter, loc, i8m2Type, "__riscv_vle8_v_i8m2",
                           mlir::ValueRange{ptr, sizeLit(lanes)}, opName, role);
        return emitOpaqueCall(rewriter, loc, i16m4Type,
                              "__riscv_vwcvt_x_x_v_i16m4",
                              mlir::ValueRange{q8i8, sizeLit(lanes)}, opName,
                              role);
      };
      // loadWeightU8: load `lanes` weight bytes at xb + byteOff as u8m2.
      auto loadWeightU8 = [&](int64_t byteOff, int64_t lanes) -> mlir::Value {
        mlir::Value ptr = byteOffsetPtr(xb, weightPtrType, byteOff, u8PtrType);
        return emitOpaqueCall(rewriter, loc, u8m2Type, "__riscv_vle8_v_u8m2",
                              mlir::ValueRange{ptr, sizeLit(lanes)}, opName,
                              role);
      };

      // ---- (A) main qs: 32 lanes, digits 0..4 -> q8[0..159] (init + 4 macc). ----
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "main_qs"));
      mlir::Value tqMain = loadWeightU8(qsOffset + 0, 32);
      mlir::Value tr0 = tritDigit(tqMain, 0, 32);
      mlir::Value q80 = q8Wide(0, 32);
      mlir::Value vacc =
          emitOpaqueCall(rewriter, loc, i16m4Type, "__riscv_vmul_vv_i16m4",
                         mlir::ValueRange{tr0, q80, sizeLit(32)}, opName, role);
      for (int64_t l = 1; l < 5; ++l) {
        mlir::Value trn = tritDigit(tqMain, l, 32);
        mlir::Value q8n = q8Wide(l * 32, 32);
        vacc = emitOpaqueCall(
            rewriter, loc, i16m4Type, "__riscv_vmacc_vv_i16m4",
            mlir::ValueRange{vacc, trn, q8n, sizeLit(32)}, opName, role);
      }

      // ---- (B) tail qs: 16 lanes, digits 0..4 -> q8[160..239] (5 macc). ----
      // The tail + qh vmacc run at vl=16 but MUST preserve the accumulator's upper
      // lanes 16..31 (the main-qs digit contributions the final vl=32 reduce sums).
      // The tail-AGNOSTIC default may clobber those lanes (the failure the P1
      // standalone dodged only by luck of scheduling); the tail-UNDISTURBED `_tu`
      // variant GUARANTEES lanes >= vl are kept -- byte-exact + VLEN-universal.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "tail_qs"));
      mlir::Value tqTail = loadWeightU8(qsOffset + 32, 16);
      for (int64_t l = 0; l < 5; ++l) {
        mlir::Value trl = tritDigit(tqTail, l, 16);
        mlir::Value q8l = q8Wide(160 + l * 16, 16);
        vacc = emitOpaqueCall(
            rewriter, loc, i16m4Type, "__riscv_vmacc_vv_i16m4_tu",
            mlir::ValueRange{vacc, trl, q8l, sizeLit(16)}, opName, role);
      }

      // ---- (C) qh: SINGLE pass, 16 lanes (4 planes x 4) -> q8[240..255]. ----
      // Read the 4 qh bytes as a little-endian uint32_t, broadcast into 4 u32
      // lanes (= 16 bytes = qh replicated x4), then multiply lane-wise by the
      // pow16 plane weights so lane j decodes qh[j%4] at power 3^(j/4). ONE vmacc
      // (replaces the retired 4-pass per-plane aux8 stores).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "qh_planes"));
      mlir::Value qhPtr = byteOffsetPtr(xb, weightPtrType, qhOffset, u8PtrType);
      mlir::Value qhByte0 =
          emitLoadByteAsUint(rewriter, loc, constU8Type, uintType, qhPtr, 0);
      mlir::Value qhByte1 =
          emitLoadByteAsUint(rewriter, loc, constU8Type, uintType, qhPtr, 1);
      mlir::Value qhByte2 =
          emitLoadByteAsUint(rewriter, loc, constU8Type, uintType, qhPtr, 2);
      mlir::Value qhByte3 =
          emitLoadByteAsUint(rewriter, loc, constU8Type, uintType, qhPtr, 3);
      mlir::Value qhWord = emitBitOr(
          rewriter, loc, uintType,
          emitBitOr(rewriter, loc, uintType, qhByte0,
                    emitBitShl(rewriter, loc, uintType, qhByte1,
                               emitUintLit(rewriter, loc, uintType, 8))),
          emitBitOr(rewriter, loc, uintType,
                    emitBitShl(rewriter, loc, uintType, qhByte2,
                               emitUintLit(rewriter, loc, uintType, 16)),
                    emitBitShl(rewriter, loc, uintType, qhByte3,
                               emitUintLit(rewriter, loc, uintType, 24))));
      mlir::Value qhBcast = emitOpaqueCallBuilt(
          rewriter, loc, u32m2Type, "__riscv_vmv_v_x_u32m2", opName, role,
          [&](mlir::OpBuilder &,
              mlir::Location) -> llvm::SmallVector<mlir::Value> {
            return {qhWord, sizeLit(4)};
          });
      mlir::Value qhBytes = emitOpaqueCall(
          rewriter, loc, u8m2Type, "__riscv_vreinterpret_v_u32m2_u8m2",
          mlir::ValueRange{qhBcast}, opName, role);
      mlir::Value pw = emitOpaqueCallBuilt(
          rewriter, loc, u8m2Type, "__riscv_vle8_v_u8m2", opName, role,
          [&](mlir::OpBuilder &,
              mlir::Location) -> llvm::SmallVector<mlir::Value> {
            mlir::Value tbl = rewriter.create<emitc::LiteralOp>(
                loc, u8PtrType, "weft_tq1_0_pow16");
            return {tbl, sizeLit(16)};
          });
      mlir::Value qhMul =
          emitOpaqueCall(rewriter, loc, u8m2Type, "__riscv_vmul_vv_u8m2",
                         mlir::ValueRange{qhBytes, pw, sizeLit(16)}, opName,
                         role);
      mlir::Value trh = tritDecode(qhMul, 16);
      mlir::Value q8h = q8Wide(240, 16);
      // vl=16 -> tail-UNDISTURBED (preserve accumulator lanes 16..31, see (B)).
      vacc = emitOpaqueCall(
          rewriter, loc, i16m4Type, "__riscv_vmacc_vv_i16m4_tu",
          mlir::ValueRange{vacc, trh, q8h, sizeLit(16)}, opName, role);

      // ---- (D) ONE reduce over the 32 active lanes -> sumi (VLEN-universal). ----
      // The fixed vl=32 bounds the sum to lanes 0..31 regardless of e16m4 VLMAX
      // (32 at VLEN128, 64 at VLEN256) -- ONE core, byte-exact on both boards.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "reduce_sumi"));
      mlir::Value redSeed = emitOpaqueCallBuilt(
          rewriter, loc, i32m1Type, "__riscv_vmv_v_x_i32m1", opName, role,
          [&](mlir::OpBuilder &,
              mlir::Location) -> llvm::SmallVector<mlir::Value> {
            mlir::Value zeroImm =
                rewriter.create<emitc::LiteralOp>(loc, i32ImmType, "0");
            return {zeroImm, sizeLit(1)};
          });
      mlir::Value red = emitOpaqueCall(
          rewriter, loc, i32m1Type, "__riscv_vwredsum_vs_i16m4_i32m1",
          mlir::ValueRange{vacc, redSeed, sizeLit(32)}, opName, role);
      // int sumi = __riscv_vmv_x_s_i32m1_i32(red);  (the SINGLE fused reduce
      // result; the same scalar the retired aux8 chunk-loop landed in sumi, now
      // from one vwredsum -- the fold in section C is byte-unchanged).
      rewriter.create<emitc::VerbatimOp>(
          loc, localVariableComment("sumi", opName, role));
      auto sumiVar = rewriter.create<emitc::VariableOp>(
          loc, emitc::LValueType::get(i32Type), emitc::OpaqueAttr::get(ctx, ""));
      mlir::Value sumiVal =
          emitOpaqueCall(rewriter, loc, i32Type, "__riscv_vmv_x_s_i32m1_i32",
                         mlir::ValueRange{red}, opName, role);
      rewriter.create<emitc::AssignOp>(loc, sumiVar, sumiVal);

      // ---- (C) the SINGLE-SCALE SCALAR fp32 fold: sumf += (float)sumi * d ----
      // float dx = (float)*(const _Float16 *)(xb + 52);  -- the fp16 tq1_0
      // super-block scale (at the END of block_tq1_0, after qs[48] + qh[4]).
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "fold_scale_d"));
      mlir::Value dxAddr = xb;
      if (weightDOffset != 0)
        dxAddr = rewriter.create<emitc::AddOp>(loc, weightPtrType, xb,
                                               sizeLit(weightDOffset));
      mlir::Value dx = emitOpaqueCall(rewriter, loc, floatType, fp16ReadCallee,
                                      mlir::ValueRange{dxAddr}, opName, role,
                                      llvm::StringRef("fcvt.s.h"));

      // float dy = *(const float *)(yb + 0);  -- the fp32 q8_K activation scale.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "fold_activation_d"));
      mlir::Value dyAddr = yb;
      if (activationDOffset != 0)
        dyAddr = rewriter.create<emitc::AddOp>(loc, activationPtrType, yb,
                                               sizeLit(activationDOffset));
      mlir::Type constFloatPtrType =
          emitc::PointerType::get(emitc::OpaqueType::get(ctx, "const float"));
      mlir::Value dyPtr =
          rewriter.create<emitc::CastOp>(loc, constFloatPtrType, dyAddr)
              .getResult();
      mlir::Value dyIndex0 =
          rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
      mlir::Value dyElem =
          rewriter
              .create<emitc::SubscriptOp>(
                  loc, llvm::cast<mlir::TypedValue<emitc::PointerType>>(dyPtr),
                  dyIndex0)
              .getResult();
      mlir::Type constFloatType = emitc::OpaqueType::get(ctx, "const float");
      mlir::Value dy =
          rewriter.create<emitc::LoadOp>(loc, constFloatType, dyElem)
              .getResult();

      // float d = dx * dy;  -- the single super-block scale, its OWN product
      // (mirrors _generic's `(GGML_CPU_FP16_TO_FP32(x[i].d) * y[i].d)`: the fp16
      // weight scale FIRST, then the fp32 activation scale).
      mlir::Value d =
          rewriter.create<emitc::MulOp>(loc, floatType, dx, dy).getResult();

      // sumf = sumf + (float)sumi * d;  -- ONE emitc.expression so the cast +
      // the product + the add render as ggml's single C statement (quants.c:476
      // `sumf += (float) sum * (...)`) and track its contraction.
      rewriter.create<emitc::VerbatimOp>(
          loc, stepComment(opName, role, "scalar_fold"));
      mlir::Value sumiFinal =
          rewriter.create<emitc::LoadOp>(loc, i32Type, sumiVar).getResult();
      mlir::Value sumfCur =
          rewriter.create<emitc::LoadOp>(loc, floatType, sumfVar).getResult();
      auto foldExpr = rewriter.create<emitc::ExpressionOp>(
          loc, floatType, /*do_not_inline=*/false);
      {
        mlir::OpBuilder::InsertionGuard exprGuard(rewriter);
        mlir::Block *exprBlock = rewriter.createBlock(&foldExpr.getRegion());
        rewriter.setInsertionPointToStart(exprBlock);
        // (float)sumi  -- the int->float conversion.
        mlir::Value sumiFloat =
            rewriter.create<emitc::CastOp>(loc, floatType, sumiFinal)
                .getResult();
        // (float)sumi * d  -- the super-block term.
        mlir::Value term =
            rewriter.create<emitc::MulOp>(loc, floatType, sumiFloat, d);
        // sumf + (float)sumi * d  -- the `+=`.
        mlir::Value sumfNext =
            rewriter.create<emitc::AddOp>(loc, floatType, sumfCur, term);
        rewriter.create<emitc::YieldOp>(loc, sumfNext);
      }
      rewriter.create<emitc::VerbatimOp>(
          loc, assignComment("sumf", opName, role));
      rewriter.create<emitc::AssignOp>(loc, sumfVar, foldExpr.getResult());
    }

    // *s = sumf;  (structured scalar store through the float * output pointer).
    // The LoadOp of the carried sumf is emitted BEFORE the output subscript, exactly
    // as the retired monolith emitted it, so the emit is byte-identical.
    mlir::Value sumf =
        rewriter.create<emitc::LoadOp>(loc, floatType, sumfVar).getResult();
    auto outPointer =
        llvm::dyn_cast<mlir::TypedValue<emitc::PointerType>>(output);
    if (!outPointer)
      return rewriter.notifyMatchFailure(
          loopBody, "tq1_0 super-block scalar-accumulator ternary output not a "
                    "pointer");
    rewriter.create<emitc::VerbatimOp>(
        loc, stepComment(opName, role, "store_s"));
    mlir::Value outIndex =
        rewriter.create<emitc::LiteralOp>(loc, rewriter.getIndexType(), "0");
    emitc::SubscriptOp outSubscript =
        rewriter.create<emitc::SubscriptOp>(loc, outPointer, outIndex);
    rewriter.create<emitc::AssignOp>(loc, outSubscript.getResult(), sumf);

    return mlir::success();
  }

} // namespace detail
} // namespace rvv
} // namespace conversion
} // namespace weft
