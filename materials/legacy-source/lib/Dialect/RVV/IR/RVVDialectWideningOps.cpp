//===- RVVDialectWideningOps.cpp - RVV op verifiers -===//
//
// Hand-written verify() methods for the RVV dialect's widening / contraction ops: WideningMAcc, WideningDotReduce, WideningProduct.
// Relocated byte-identical from RVVDialect.cpp; no logic change. Shared
// verification helpers and per-op metadata predicates are declared in
// RVVDialectInternal.h (definitions remain in RVVDialect.cpp's single TU,
// alongside the generated *.cpp.inc op-class bodies).
//
// Ops: widening / contraction ops: WideningMAcc, WideningDotReduce, WideningProduct,
// PackedI4NibbleUnpackProduct, MaskedWideningDotReduce, WideningConvert,
// Dequantize
//
//===----------------------------------------------------------------------===//

#include "RVVDialectInternal.h"

#include "Weft/Conversion/EmitC/TunableScheduleOpInterface.h"
#include "Weft/Dialect/Exec/IR/ExecOps.h"
#include "Weft/Dialect/RVV/IR/RVVConfigContract.h"
#include "Weft/Dialect/RVV/IR/RVVDialect.h"
#include "Weft/Plugin/RVV/RVVGearboxSchedule.h"
#include "Weft/Support/CapabilityModel.h"
#include "Weft/Support/GridDecodePlan.h"
#include "Weft/Support/RuntimeABI.h"

#include "mlir/IR/Builders.h"
#include "mlir/IR/SymbolTable.h"
#include "llvm/ADT/STLExtras.h"
#include "llvm/ADT/SmallPtrSet.h"
#include "llvm/ADT/SmallVector.h"
#include "llvm/ADT/StringRef.h"
#include "llvm/ADT/Twine.h"
#include "llvm/Support/raw_ostream.h"

#include <cstdint>
#include <functional>
#include <initializer_list>
#include <optional>
#include <string>

using namespace weft::rvv;

mlir::LogicalResult WideningMAccOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.widening_macc keeps source/result "
                "SEW/LMUL/policy on typed vector values and setvl/with_vl, "
                "runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";

    if (!isAllowedWideningMAccAttr(attrName))
      return emitOpError()
             << "only accepts generic widening multiply-accumulate "
                "attributes 'kind', 'accumulator_layout', 'result_layout', "
                "and 'macc_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericWideningMAccKind(getKind()))
    return emitOpError()
           << "currently supports only kind \"signed_widening_macc_add\" for "
              "the bounded Stage 2 widening multiply-accumulate route";
  if (!isSupportedGenericWideningMAccAccumulatorLayout(
          getAccumulatorLayout()))
    return emitOpError()
           << "currently supports only accumulator_layout "
              "\"separate-i32-vector-accumulator-input\" for the bounded "
              "Stage 2 widening multiply-accumulate route";
  if (!isSupportedGenericWideningMAccResultLayout(getResultLayout()))
    return emitOpError()
           << "currently supports only result_layout "
              "\"store-widening-multiply-accumulate-result-to-output-buffer\" "
              "for the bounded Stage 2 widening multiply-accumulate route";
  if (!isSupportedGenericWideningMAccRelation(getMaccRelation()))
    return emitOpError()
           << "currently supports only macc_relation "
              "\"signed-i16mf2xi16mf2-plus-i32m1-to-i32m1\" for the bounded "
              "Stage 2 widening multiply-accumulate route";

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires lhs and rhs i16 generic RVV vector operands, one i32 "
              "accumulator vector operand, one !weft_rvv.vl operand, and one "
              "i32 generic RVV vector result";
  if (!isGenericRVVVectorI16MF2(getLhs().getType()) ||
      !isGenericRVVVectorI16MF2(getRhs().getType()))
    return emitOpError()
           << "requires lhs and rhs source vectors to have type "
              "!weft_rvv.vector<i16, \"mf2\"> for the bounded signed "
              "widening multiply-accumulate route";
  if (!isGenericRVVVectorI32M1(getAccumulator().getType()) ||
      !isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires accumulator and result vectors to have type "
              "!weft_rvv.vector<i32, \"m1\"> for the bounded signed widening "
              "multiply-accumulate route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit "
              "accumulator/result SEW/LMUL metadata for widening macc";
  if (!isRVVSelectedBodyM1Config(expectedSEW.getInt(),
                                 expectedLMUL.getValue()))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl accumulator/result config "
              "to be SEW32 LMUL m1 for the bounded signed widening macc "
              "route";
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for widening macc";

  return mlir::success();
}

mlir::LogicalResult WideningDotReduceOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.widening_dot_reduce keeps source/result "
                "SEW/LMUL/policy on typed vector values and setvl/with_vl, "
                "runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";

    if (!isAllowedWideningDotReduceAttr(attrName))
      return emitOpError()
             << "only accepts generic widening dot-product reduction "
                "attributes 'kind', 'accumulator_layout', 'result_layout', "
                "and 'dot_product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericWideningDotReduceKind(getKind()))
    return emitOpError()
           << "currently supports only kind "
              "\"signed_widening_dot_reduce_add\" for the bounded Stage 2 "
              "widening dot-product reduction route";
  if (!isSupportedGenericWideningDotReduceAccumulatorLayout(
          getAccumulatorLayout()))
    return emitOpError()
           << "currently supports only accumulator_layout "
              "\"scalar-i32-seed-lane0-from-accumulator-input\" for the "
              "bounded Stage 2 widening dot-product reduction route";
  if (!isSupportedGenericWideningDotReduceResultLayout(getResultLayout()))
    return emitOpError()
           << "currently supports only result_layout "
              "\"store-dot-reduction-lane0-to-output-scalar\" for the "
              "bounded Stage 2 widening dot-product reduction route";
  if (!isSupportedGenericWideningDotProductRelation(
          getDotProductRelation()))
    return emitOpError()
           << "currently supports only dot_product_relation "
              "\"signed-i16mf2xi16mf2-reduce-plus-i32-scalar-to-i32\" for "
              "the bounded Stage 2 widening dot-product reduction route";

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires lhs and rhs i16 generic RVV vector operands, one i32 "
              "accumulator seed runtime ABI operand, one !weft_rvv.vl "
              "operand, and one i32 generic RVV vector result";
  if (!isGenericRVVVectorI16MF2(getLhs().getType()) ||
      !isGenericRVVVectorI16MF2(getRhs().getType()))
    return emitOpError()
           << "requires lhs and rhs source vectors to have type "
              "!weft_rvv.vector<i16, \"mf2\"> for the bounded signed "
              "widening dot-product reduction route";
  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type "
              "!weft_rvv.vector<i32, \"m1\"> for the bounded signed "
              "widening dot-product reduction route";
  if (!llvm::isa<RuntimeABIValueType>(getAccumulatorSeed().getType()))
    return emitOpError()
           << "requires accumulator seed operand to have "
              "!weft_rvv.runtime_abi_value type";
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getAccumulatorSeed(), "accumulator seed",
          {weft::support::RuntimeABIParameterRole::
               AccumulatorInputBuffer})))
    return mlir::failure();
  RuntimeABIValueOp seedBinding =
      getAccumulatorSeed().getDefiningOp<RuntimeABIValueOp>();
  if (!seedBinding || seedBinding.getCType() != "const int32_t *")
    return emitOpError()
           << "requires accumulator seed operand C type 'const int32_t *' "
              "for the bounded signed widening dot-product reduction route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit "
              "result SEW/LMUL metadata for widening dot-product reduction";
  if (!isRVVSelectedBodyM1Config(expectedSEW.getInt(),
                                 expectedLMUL.getValue()))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl result config to be "
              "SEW32 LMUL m1 for the bounded signed widening dot-product "
              "reduction route";
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for widening dot-product reduction";

  return mlir::success();
}

mlir::LogicalResult WideningProductOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.widening_product keeps source/result "
                "SEW/LMUL/policy on typed vector values and setvl/with_vl, "
                "runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";

    if (!isAllowedWideningProductAttr(attrName))
      return emitOpError()
             << "only accepts generic widening product attributes 'kind' and "
                "'product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericWideningProductKind(getKind()))
    return emitOpError()
           << "currently supports only kind \"signed_widening_product\" or "
              "\"unsigned_widening_product\" for the bounded Stage 2 "
              "low-precision widening-product typed surface";
  if (!isSupportedGenericWideningProductRelation(getProductRelation()))
    return emitOpError()
           << "currently supports only product_relation "
              "\"signed-i8mf4xi8mf4-to-i16mf2\", "
              "\"unsigned-u8mf4xu8mf4-to-u16mf2\", or "
              "\"signed-i8m2xi8m2-to-i16m4\" (the deferred-wide max-legal-LMUL "
              "rung) for the bounded Stage 2 low-precision widening-product "
              "typed surface";

  if (op->getNumOperands() != 3 || op->getNumResults() != 1)
    return emitOpError()
           << "requires lhs and rhs i8 generic RVV vector operands, one "
              "!weft_rvv.vl operand, and one i16 generic RVV vector result";
  const bool isUnsignedProduct = getKind() == "unsigned_widening_product";
  // The deferred-wide max-legal-LMUL rung (N3 schedule, the measured ssh-rvv
  // winner): i8m2 x i8m2 -> i16m4 feeding weft_rvv.widening_accumulate. This is
  // a PARALLEL signed verifier branch -- the narrow i8mf4 branch is unchanged.
  const bool isWideDeferredProduct =
      getKind() == "signed_widening_product" &&
      isSupportedGenericWideningProductWideDeferredRelation(getProductRelation());
  if (isWideDeferredProduct) {
    if (!isGenericRVVVectorSignedI8M2(getLhs().getType()) ||
        !isGenericRVVVectorSignedI8M2(getRhs().getType()))
      return emitOpError()
             << "requires lhs and rhs source vectors to have type "
                "!weft_rvv.vector<i8, \"m2\"> for the deferred-wide "
                "max-legal-LMUL widening-product rung";
    if (!isGenericRVVVectorSignedI16M4(getResult().getType()))
      return emitOpError()
             << "requires result vector to have type "
                "!weft_rvv.vector<i16, \"m4\"> for the deferred-wide "
                "max-legal-LMUL widening-product rung";
    if (!llvm::isa<VLType>(getVl().getType()))
      return emitOpError() << "requires runtime VL operand to have "
                              "!weft_rvv.vl type";
    auto withVL = verifyNestedDataflowOp(op);
    if (mlir::failed(withVL))
      return mlir::failure();
    if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
      return mlir::failure();
    auto expectedSEW =
        (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
    auto expectedLMUL =
        (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
    if (!expectedSEW || !expectedLMUL)
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl to carry explicit "
                "SEW/LMUL metadata for the deferred-wide widening product";
    if (expectedSEW.getInt() != getRVVSEW8Bits() ||
        expectedLMUL.getValue() != getRVVLMULM2())
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl config to be SEW8 LMUL m2 "
                "for the deferred-wide max-legal-LMUL widening-product rung";
    if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl to carry explicit policy "
                "metadata for widening product";
    return mlir::success();
  }
  // The Track B byte-anchor dot-reduce m1 rung (e8m1 anchor, VLEN256): i8m1 x
  // i8m1 -> i16m2 feeding weft_rvv.standalone_reduce. PARALLEL signed branch; the
  // i8m2 rung above (e8m2, VLEN128) and the narrow i8mf4 branch are unchanged.
  // (The m2 byte-anchor dot-reduce reuses the isWideDeferredProduct branch above
  // -- the i8m2 -> i16m4 product type-check is identical; only the consumer op
  // differs, which the load/reduce verifiers gate.)
  const bool isByteAnchorM1Product =
      getKind() == "signed_widening_product" &&
      getProductRelation() == "signed-i8m1xi8m1-to-i16m2";
  if (isByteAnchorM1Product) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            getLhs().getType(), getRVVSEW8Bits(), getRVVLMULM1()) ||
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            getRhs().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
      return emitOpError()
             << "requires lhs and rhs source vectors to have type "
                "!weft_rvv.vector<i8, \"m1\"> for the byte-anchor m1 "
                "widening-product dot-reduce rung";
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            getResult().getType(), getRVVSEW16Bits(), getRVVLMULM2()))
      return emitOpError()
             << "requires result vector to have type "
                "!weft_rvv.vector<i16, \"m2\"> for the byte-anchor m1 "
                "widening-product dot-reduce rung";
    if (!llvm::isa<VLType>(getVl().getType()))
      return emitOpError() << "requires runtime VL operand to have "
                              "!weft_rvv.vl type";
    auto withVL = verifyNestedDataflowOp(op);
    if (mlir::failed(withVL))
      return mlir::failure();
    if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
      return mlir::failure();
    auto expectedSEW =
        (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
    auto expectedLMUL =
        (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
    if (!expectedSEW || !expectedLMUL)
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl to carry explicit "
                "SEW/LMUL metadata for the byte-anchor widening product";
    if (expectedSEW.getInt() != getRVVSEW8Bits() ||
        expectedLMUL.getValue() != getRVVLMULM1())
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl config to be SEW8 LMUL m1 "
                "for the byte-anchor m1 widening-product dot-reduce rung";
    if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl to carry explicit policy "
                "metadata for widening product";
    return mlir::success();
  }
  // The 2nd-family (i16 dot-reduce) deferred-wide rung: i16m4 x i16m4 -> i32m8,
  // a SINGLE widening step where the widened product already equals the i32
  // accumulator width. Feeds a NON-widening weft_rvv.deferred_accumulate
  // (vadd.vv). PARALLEL signed branch -- the byte i8m2 and narrow i8mf4 branches
  // are unchanged.
  const bool isWideDotReduceProduct =
      getKind() == "signed_widening_product" &&
      isSupportedGenericWideningProductWideDotReduceRelation(
          getProductRelation());
  if (isWideDotReduceProduct) {
    // Derive the expected source/accumulator LMUL from the (validated) relation
    // rather than pinning m4/m8: the budget-driven LMUL-width ablation realizes
    // the wide m4/m8 rung at the default budget and a narrower m2/m4 or mf2/m1
    // rung at a constrained budget. The source i16 LMUL is parsed from the
    // relation and the i32 accumulator is its next-wider step; the operand,
    // result, and enclosing with_vl config must all carry that exact LMUL.
    const llvm::StringRef sourceLMUL =
        getRVVDotReduceProductSourceLMUL(getProductRelation());
    const llvm::StringRef accumulatorLMUL =
        weft::plugin::rvv::getRVVNextWiderLMUL(sourceLMUL);
    if (sourceLMUL.empty() || accumulatorLMUL.empty())
      return emitOpError()
             << "requires a supported deferred-wide dot-reduce "
                "product_relation \"signed-i16<L>xi16<L>-to-i32<W>\"";
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            getLhs().getType(), getRVVSEW16Bits(), sourceLMUL) ||
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            getRhs().getType(), getRVVSEW16Bits(), sourceLMUL))
      return emitOpError()
             << "requires lhs and rhs source vectors to have type "
                "!weft_rvv.vector<i16, \""
             << sourceLMUL
             << "\"> matching the deferred-wide dot-reduce product_relation "
                "source LMUL";
    if (!isGenericRVVVectorType(getResult().getType(), getRVVSEW32Bits(),
                                accumulatorLMUL))
      return emitOpError()
             << "requires result vector to have type !weft_rvv.vector<i32, \""
             << accumulatorLMUL
             << "\"> matching the deferred-wide dot-reduce product_relation "
                "accumulator LMUL";
    if (!llvm::isa<VLType>(getVl().getType()))
      return emitOpError() << "requires runtime VL operand to have "
                              "!weft_rvv.vl type";
    auto withVL = verifyNestedDataflowOp(op);
    if (mlir::failed(withVL))
      return mlir::failure();
    if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
      return mlir::failure();
    auto expectedSEW =
        (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
    auto expectedLMUL =
        (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
    if (!expectedSEW || !expectedLMUL)
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl to carry explicit "
                "SEW/LMUL metadata for the deferred-wide dot-reduce product";
    if (expectedSEW.getInt() != getRVVSEW16Bits() ||
        expectedLMUL.getValue() != sourceLMUL)
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl config to be SEW16 LMUL "
             << sourceLMUL
             << " matching the deferred-wide dot-reduce widening-product rung";
    if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl to carry explicit policy "
                "metadata for widening product";
    return mlir::success();
  }
  if (isUnsignedProduct) {
    if (getProductRelation() != "unsigned-u8mf4xu8mf4-to-u16mf2")
      return emitOpError()
             << "requires product_relation "
                "\"unsigned-u8mf4xu8mf4-to-u16mf2\" when kind is "
                "\"unsigned_widening_product\"";
    if (!isGenericRVVVectorUnsignedI8MF4(getLhs().getType()) ||
        !isGenericRVVVectorUnsignedI8MF4(getRhs().getType()))
      return emitOpError()
             << "requires lhs and rhs source vectors to have type "
                "!weft_rvv.vector<ui8, \"mf4\"> for the bounded unsigned "
                "low-precision widening-product typed surface";
    if (!isGenericRVVVectorUnsignedI16MF2(getResult().getType()))
      return emitOpError()
             << "requires result vector to have type "
                "!weft_rvv.vector<ui16, \"mf2\"> for the bounded unsigned "
                "low-precision widening-product typed surface";
  } else {
    if (getProductRelation() != "signed-i8mf4xi8mf4-to-i16mf2")
      return emitOpError()
             << "requires product_relation "
                "\"signed-i8mf4xi8mf4-to-i16mf2\" when kind is "
                "\"signed_widening_product\"";
    if (!isGenericRVVVectorSignedI8MF4(getLhs().getType()) ||
        !isGenericRVVVectorSignedI8MF4(getRhs().getType()))
      return emitOpError()
             << "requires lhs and rhs source vectors to have type "
                "!weft_rvv.vector<i8, \"mf4\"> for the bounded signed "
                "low-precision widening-product route";
    if (!isGenericRVVVectorSignedI16MF2(getResult().getType()))
      return emitOpError()
             << "requires result vector to have type "
                "!weft_rvv.vector<i16, \"mf2\"> for the bounded signed "
                "low-precision widening-product route";
  }
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit result "
              "SEW/LMUL metadata for widening product";
  const bool isStandaloneProductConfig =
      expectedSEW.getInt() == getRVVSEW16Bits() &&
      expectedLMUL.getValue() == getRVVLMULMF2();
  const bool isProductReductionChainConfig =
      isBoundedWideningProductReductionChainProduct(*this, *withVL);
  if (!isStandaloneProductConfig && !isProductReductionChainConfig)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl result config to be "
              "SEW16 LMUL mf2 for the bounded signed low-precision "
              "widening-product route, or SEW32 LMUL m1 when the i16 product "
              "feeds the bounded i16-to-i32 standalone widening reduction "
              "chain";
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for widening product";

  return mlir::success();
}

mlir::LogicalResult WideningAccumulateOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.widening_accumulate keeps source/result SEW/LMUL/"
                "policy on typed vector values and setvl/with_vl, runtime "
                "n/AVL/VL in the surrounding control-plane IR, and rejects "
                "deleted local element_count metadata";

    if (!isAllowedWideningAccumulateAttr(attrName))
      return emitOpError()
             << "only accepts generic deferred widening accumulate attributes "
                "'kind' and 'accumulate_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericWideningAccumulateKind(getKind()))
    return emitOpError()
           << "currently supports only kind "
              "\"signed_widening_accumulate_add\" for the bounded N3 "
              "deferred-wide widening accumulate route";
  if (!isSupportedGenericWideningAccumulateRelation(getAccumulateRelation()))
    return emitOpError()
           << "currently supports only accumulate_relation "
              "\"signed-i16m4-into-i32m8-deferred-add\" for the bounded N3 "
              "deferred-wide widening accumulate route";

  if (op->getNumOperands() != 2 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one i16 LMUL m4 widening-product operand, one "
              "!weft_rvv.vl operand, and one i32 LMUL m8 vector result";
  if (!isGenericRVVVectorSignedI16M4(getProduct().getType()))
    return emitOpError()
           << "requires product operand to have type "
              "!weft_rvv.vector<i16, \"m4\"> for the deferred-wide widening "
              "accumulate route";
  if (!isGenericRVVVectorI32M8(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type "
              "!weft_rvv.vector<i32, \"m8\"> for the deferred-wide widening "
              "accumulate route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  // The deferred-wide accumulate consumes a bounded i8m2 x i8m2 -> i16m4 signed
  // widening product (the structural marker that the body is the deferred-wide
  // algorithm). This keeps emission body-determined (I5): the conversion does
  // not infer the deferred mode from metadata, it follows op identity.
  auto product = getProduct().getDefiningOp<WideningProductOp>();
  if (!product)
    return emitOpError()
           << "requires product operand to be produced by a bounded "
              "weft_rvv.widening_product inside the selected RVV typed body";
  if (product.getKind() != "signed_widening_product" ||
      !isSupportedGenericWideningProductWideDeferredRelation(
          product.getProductRelation()))
    return emitOpError()
           << "requires product-producing weft_rvv.widening_product to use "
              "kind \"signed_widening_product\" and product_relation "
              "\"signed-i8m2xi8m2-to-i16m4\" for the deferred-wide widening "
              "accumulate route";
  if (product.getVl() != getVl())
    return emitOpError()
           << "requires product-producing weft_rvv.widening_product to consume "
              "the same !weft_rvv.vl token as weft_rvv.widening_accumulate";
  if (product->getParentOp() != op->getParentOp())
    return emitOpError()
           << "requires product-producing weft_rvv.widening_product to be in "
              "the same weft_rvv.with_vl body as weft_rvv.widening_accumulate";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit SEW/LMUL "
              "metadata for the deferred-wide widening accumulate";
  if (expectedSEW.getInt() != getRVVSEW8Bits() ||
      expectedLMUL.getValue() != getRVVLMULM2())
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl config to be SEW8 LMUL m2 "
              "for the deferred-wide max-legal-LMUL widening accumulate route";
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the deferred-wide widening accumulate";

  return mlir::success();
}

mlir::LogicalResult DeferredAccumulateOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.deferred_accumulate keeps source/result SEW/LMUL/"
                "policy on typed vector values and setvl/with_vl, runtime "
                "n/AVL/VL in the surrounding control-plane IR, and rejects "
                "deleted local element_count metadata";

    if (!isAllowedDeferredAccumulateAttr(attrName))
      return emitOpError()
             << "only accepts generic deferred accumulate attributes "
                "'kind' and 'accumulate_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericDeferredAccumulateKind(getKind()))
    return emitOpError()
           << "currently supports only kind "
              "\"signed_deferred_accumulate_add\" for the bounded N3 "
              "deferred-wide dot-reduce accumulate route";
  if (!isSupportedGenericDeferredAccumulateRelation(getAccumulateRelation()))
    return emitOpError()
           << "currently supports only accumulate_relation "
              "\"signed-i32m8-into-i32m8-deferred-add\" for the bounded N3 "
              "deferred-wide dot-reduce accumulate route";

  // Derive the i32 accumulator LMUL from the (validated) accumulate_relation,
  // not pinning m8: the budget-driven LMUL-width ablation realizes the wide m8
  // accumulator at the default budget and a narrower m4 or m1 accumulator at a
  // constrained budget. Operand and result must both be i32 at that exact LMUL
  // (same-width vadd.vv aliases the product into the accumulator).
  const llvm::StringRef accumulatorLMUL =
      getRVVDotReduceAccumulateLMUL(getAccumulateRelation());
  if (accumulatorLMUL.empty())
    return emitOpError()
           << "requires a supported deferred-wide dot-reduce accumulate_relation "
              "\"signed-i32<W>-into-i32<W>-deferred-add\"";

  if (op->getNumOperands() != 2 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one i32 widening-product operand, one !weft_rvv.vl "
              "operand, and one i32 vector result";
  if (!isGenericRVVVectorType(getProduct().getType(), getRVVSEW32Bits(),
                              accumulatorLMUL))
    return emitOpError()
           << "requires product operand to have type !weft_rvv.vector<i32, \""
           << accumulatorLMUL
           << "\"> matching the deferred-wide dot-reduce accumulate_relation";
  if (!isGenericRVVVectorType(getResult().getType(), getRVVSEW32Bits(),
                              accumulatorLMUL))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, \""
           << accumulatorLMUL
           << "\"> matching the deferred-wide dot-reduce accumulate_relation";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  // The deferred-wide dot-reduce accumulate consumes a bounded i16<L> x i16<L> ->
  // i32<W> signed widening product (the structural marker that the body is the
  // deferred-wide dot-reduce algorithm). The product's accumulator LMUL <W> must
  // MATCH this op's accumulate_relation <W>. This keeps emission body-determined
  // (I5): the conversion follows op identity, not metadata.
  auto product = getProduct().getDefiningOp<WideningProductOp>();
  if (!product)
    return emitOpError()
           << "requires product operand to be produced by a bounded "
              "weft_rvv.widening_product inside the selected RVV typed body";
  const llvm::StringRef productSourceLMUL =
      getRVVDotReduceProductSourceLMUL(product.getProductRelation());
  if (product.getKind() != "signed_widening_product" ||
      productSourceLMUL.empty() ||
      weft::plugin::rvv::getRVVNextWiderLMUL(productSourceLMUL) !=
          accumulatorLMUL)
    return emitOpError()
           << "requires product-producing weft_rvv.widening_product to use "
              "kind \"signed_widening_product\" and a product_relation "
              "\"signed-i16<L>xi16<L>-to-i32"
           << accumulatorLMUL
           << "\" matching the deferred-wide dot-reduce accumulate route";
  if (product.getVl() != getVl())
    return emitOpError()
           << "requires product-producing weft_rvv.widening_product to consume "
              "the same !weft_rvv.vl token as weft_rvv.deferred_accumulate";
  if (product->getParentOp() != op->getParentOp())
    return emitOpError()
           << "requires product-producing weft_rvv.widening_product to be in "
              "the same weft_rvv.with_vl body as weft_rvv.deferred_accumulate";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit SEW/LMUL "
              "metadata for the deferred-wide dot-reduce accumulate";
  // The enclosing with_vl strip config is the i16 SOURCE LMUL <L> (the product
  // source), not the i32 accumulator <W>.
  if (expectedSEW.getInt() != getRVVSEW16Bits() ||
      expectedLMUL.getValue() != productSourceLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl config to be SEW16 LMUL "
           << productSourceLMUL
           << " matching the deferred-wide dot-reduce accumulate route";
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the deferred-wide dot-reduce accumulate";

  return mlir::success();
}

mlir::LogicalResult PackedI4NibbleUnpackProductOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.packed_i4_nibble_unpack_product keeps source/"
                "result SEW/LMUL/policy on typed vector values and "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";

    if (!isAllowedWideningProductAttr(attrName))
      return emitOpError()
             << "only accepts generic widening product attributes 'kind' and "
                "'product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "signed_packed_i4_nibble_unpack_product")
    return emitOpError()
           << "currently supports only kind "
              "\"signed_packed_i4_nibble_unpack_product\" for the bounded "
              "Stage 3 packed-i4 nibble-unpack widening-product typed surface";
  if (getProductRelation() != "signed-i8mf4xi8mf4-to-i16mf2")
    return emitOpError()
           << "requires product_relation "
              "\"signed-i8mf4xi8mf4-to-i16mf2\" for the bounded packed-i4 "
              "nibble-unpack widening-product route";

  if (op->getNumOperands() != 3 || op->getNumResults() != 1)
    return emitOpError()
           << "requires two i8 LMUL mf4 packed source operands, one "
              "!weft_rvv.vl operand, and one i16 LMUL mf2 result";
  if (!isGenericRVVVectorSignedI8MF4(getLhs().getType()) ||
      !isGenericRVVVectorSignedI8MF4(getRhs().getType()))
    return emitOpError()
           << "requires lhs and rhs source vectors to have type "
              "!weft_rvv.vector<i8, \"mf4\"> for the bounded packed-i4 "
              "nibble-unpack widening-product route";
  if (!isGenericRVVVectorSignedI16MF2(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type "
              "!weft_rvv.vector<i16, \"mf2\"> for the bounded packed-i4 "
              "nibble-unpack widening-product route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for packed-i4 nibble-unpack widening product";

  return mlir::success();
}

mlir::LogicalResult PackedI4OffsetBinaryXI8ProductOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.packed_i4_offset_binary_x_i8_product keeps source/"
                "result SEW/LMUL/policy on typed vector values and "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";

    if (!isAllowedWideningProductAttr(attrName))
      return emitOpError()
             << "only accepts generic widening product attributes 'kind' and "
                "'product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "signed_packed_i4_offset_binary_x_i8_product")
    return emitOpError()
           << "currently supports only kind "
              "\"signed_packed_i4_offset_binary_x_i8_product\" for the bounded "
              "Stage 4 asymmetric offset-binary packed-i4 x plain-i8 "
              "widening-product typed surface";
  // Two LMUL rungs share the SAME offset-binary decode + asymmetric widening
  // product STRUCTURE; only the vector width differs. The narrow mf4/mf2 rung is
  // the INC-1 integer-core anchor; the m1/m2 rung is the M-FLAT flat-cohort core
  // (i4m1 weight x i8m1 low/high activation -> i16m2). This mirrors how
  // weft_rvv.widening_product declares multiple LMUL rungs; the emitter derives
  // every intrinsic width from the operand/result types, so the m1 rung is
  // byte-exact to the mf4 rung modulo the width tokens.
  const bool isNarrowRung =
      getProductRelation() == "offset-binary-i4mf4-x-i8mf4x2-to-i16mf2";
  const bool isM1Rung =
      getProductRelation() == "offset-binary-i4m1-x-i8m1x2-to-i16m2";
  if (!isNarrowRung && !isM1Rung)
    return emitOpError()
           << "requires product_relation "
              "\"offset-binary-i4mf4-x-i8mf4x2-to-i16mf2\" (the narrow "
              "integer-core rung) or \"offset-binary-i4m1-x-i8m1x2-to-i16m2\" "
              "(the m1 flat-cohort rung) for the bounded asymmetric "
              "offset-binary packed-i4 x plain-i8 widening-product route";

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one packed-i4 weight operand, two plain-int8 "
              "activation operands, one !weft_rvv.vl operand, and one widened "
              "i16 result";
  if (isM1Rung) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            getWeight().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
      return emitOpError()
             << "requires the packed-i4 weight source vector to have type "
                "!weft_rvv.vector<i8, \"m1\"> for the m1 asymmetric "
                "offset-binary packed-i4 x plain-i8 widening-product rung";
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            getActivationLow().getType(), getRVVSEW8Bits(), getRVVLMULM1()) ||
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            getActivationHigh().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
      return emitOpError()
             << "requires the low and high plain-int8 activation source vectors "
                "to have type !weft_rvv.vector<i8, \"m1\"> for the m1 "
                "asymmetric offset-binary packed-i4 x plain-i8 "
                "widening-product rung";
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            getResult().getType(), getRVVSEW16Bits(), getRVVLMULM2()))
      return emitOpError()
             << "requires result vector to have type "
                "!weft_rvv.vector<i16, \"m2\"> for the m1 asymmetric "
                "offset-binary packed-i4 x plain-i8 widening-product rung";
  } else {
    if (!isGenericRVVVectorSignedI8MF4(getWeight().getType()))
      return emitOpError()
             << "requires the packed-i4 weight source vector to have type "
                "!weft_rvv.vector<i8, \"mf4\"> for the asymmetric offset-binary "
                "packed-i4 x plain-i8 widening-product route";
    if (!isGenericRVVVectorSignedI8MF4(getActivationLow().getType()) ||
        !isGenericRVVVectorSignedI8MF4(getActivationHigh().getType()))
      return emitOpError()
             << "requires the low and high plain-int8 activation source vectors "
                "to have type !weft_rvv.vector<i8, \"mf4\"> for the asymmetric "
                "offset-binary packed-i4 x plain-i8 widening-product route";
    if (!isGenericRVVVectorSignedI16MF2(getResult().getType()))
      return emitOpError()
             << "requires result vector to have type "
                "!weft_rvv.vector<i16, \"mf2\"> for the asymmetric offset-binary "
                "packed-i4 x plain-i8 widening-product route";
  }
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for asymmetric offset-binary packed-i4 x plain-i8 "
              "widening product";

  return mlir::success();
}

mlir::LogicalResult RepackLaneWiseQ4Q8DotOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // within-block byte offsets the per-block lane-wise nibble dot needs, and the
  // OPTIONAL integer_core_lmul resource anchor. The per-block strides, qk, the
  // interleave, and the resource-aware strip width are the enclosing loop op's
  // facts. A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul" || name == "weight_nibble_unsigned" ||
           name == "weight_qh_byte_offset" || name == "weight_offset_bias" ||
           name == "weight_full_i8";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_lane_wise_q4_x_i8_dot keeps SEW/LMUL/policy "
                "on setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded repacked lane-wise dot attributes "
                "'kind', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'integer_core_lmul', the "
                "optional q4_1 'weight_nibble_unsigned' decode selector, the "
                "optional q5_0 'weight_qh_byte_offset' / 'weight_offset_bias' "
                "5th-bit decode facts, and the optional q8_0 'weight_full_i8' "
                "full-int8 decode selector; unexpected attribute '"
             << attr.getName() << "'";
  }

  // OPTIONAL q8_0 FULL-int8 decode selector (I7): the SIMPLEST flat decode (no
  // nibble unpack, i32 in-block accumulation over qk positions). It is mutually
  // exclusive with the nibble decode selectors -- the full-i8 core has no nibble
  // lo/hi split, no unsigned peel, and no qh 5th-bit plane.
  if (getWeightFullI8()) {
    if (getWeightNibbleUnsigned() || getWeightQhByteOffsetAttr() ||
        getWeightOffsetBiasAttr())
      return emitOpError()
             << "weight_full_i8 (the q8_0 full-int8 decode) is mutually exclusive "
                "with the nibble decode selectors weight_nibble_unsigned / "
                "weight_qh_byte_offset / weight_offset_bias";
  }

  // OPTIONAL 5th-bit (qh) decode facts (I7): the transposed qh plane byte offset +
  // an OPTIONAL offset-binary centering bias. The qh plane assembles the 5-bit
  // weight `(nibble) | (qh_bit << 4)` off a RAW unsigned nibble peel, so
  // weight_nibble_unsigned must also be set. The bias is q5_0's `-16` offset-binary
  // centering (`... - 16`, weights in [-16,15]); q5_1 carries NO bias (UNSIGNED
  // weights in [0,31], the asymmetric bias living in the separate per-block MIN
  // scale). So: qh may appear WITH bias (q5_0) OR WITHOUT bias (q5_1); a bias with
  // NO qh is meaningless and rejected. Each fact, when present, must be positive.
  {
    mlir::IntegerAttr qhAttr = getWeightQhByteOffsetAttr();
    mlir::IntegerAttr biasAttr = getWeightOffsetBiasAttr();
    if (biasAttr && !qhAttr)
      return emitOpError()
             << "requires weight_offset_bias only TOGETHER with "
                "weight_qh_byte_offset (the offset-binary centering bias is "
                "meaningless without the qh 5th-bit plane)";
    if (qhAttr) {
      if (!getWeightNibbleUnsigned())
        return emitOpError()
               << "requires weight_nibble_unsigned when carrying the "
                  "weight_qh_byte_offset (the 5-bit weight assembles off the RAW "
                  "unsigned nibble peel)";
      if (qhAttr.getInt() <= 0)
        return emitOpError() << "requires weight_qh_byte_offset > 0 (the qh "
                                "SECOND weight-plane byte offset); got "
                             << qhAttr.getInt();
      if (biasAttr && biasAttr.getInt() <= 0)
        return emitOpError() << "requires weight_offset_bias > 0 (the q5_0 "
                                "offset-binary centering bias); got "
                             << biasAttr.getInt();
    }
  }

  if (getKind() != "repack_lane_wise_q4_x_i8_dot")
    return emitOpError()
           << "currently supports only kind \"repack_lane_wise_q4_x_i8_dot\" for "
              "the bounded q4_0 16x1-repacked per-block lane-wise nibble-dot "
              "integer-core typed surface";

  // Bounded resource knob (the *how*, never the *what*): the integer-core
  // widening-chain base LMUL {"mf2" RVV1.0 fractional, "m1" RVV0.7 whole-LMUL}.
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 fractional "
                "chain) or \"m1\" (the RVV0.7 whole-LMUL chain); got \""
             << coreLmul << "\"";
  }

  if (op->getNumOperands() != 4 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked weight base, the plain q8_0 activation "
              "base, one !weft_rvv.vl operand, one block_index induction "
              "operand, and one or more per-strip i32 vector results (one per "
              "disjoint strip -- numHalves total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  // Each per-strip combined sumi widens the i16 lo/hi accumulators one LMUL rung:
  // i32m2 for the mf2 (RVV1.0 fractional) core, i32m4 for the m1 (RVV0.7
  // whole-LMUL) core. Every strip shares the ONE integer-core LMUL rung.
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-strip result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-strip 16-lane combined sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-strip results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise nibble-dot integer core";

  return mlir::success();
}

// Shared allow-list + decode/lmul checks for the two ternary repack core bricks
// (GEVM/GEMM). The bounded local attrs are 'kind', 'decode_model', the two
// within-block byte offsets, and the OPTIONAL integer_core_lmul resource anchor.
static mlir::LogicalResult
verifyRepackTernaryCoreCommon(mlir::Operation *op,
                              const std::function<mlir::InFlightDiagnostic()> &err,
                              llvm::StringRef expectedKind,
                              llvm::StringRef kindGot,
                              llvm::StringRef decodeModel,
                              std::optional<llvm::StringRef> coreLmul) {
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "decode_model" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return err()
             << "does not accept attribute '" << attr.getName()
             << "'; the ternary repack core keeps SEW/LMUL/policy on "
                "setvl/with_vl and runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return err() << "only accepts the bounded ternary repack core attributes "
                      "'kind', 'decode_model', 'weight_quant_byte_offset', "
                      "'activation_quant_byte_offset', and 'integer_core_lmul'; "
                      "unexpected attribute '"
                   << attr.getName() << "'";
  }
  if (kindGot != expectedKind)
    return err() << "currently supports only kind \"" << expectedKind
                 << "\" for the bounded ternary 16x1-repacked per-block "
                    "lane-wise trit-dot integer-core typed surface";
  // The bounded ternary decode family: tq2_0 (2-bit field) or tq1_0 (base-3).
  if (decodeModel != "tq2_0" && decodeModel != "tq1_0")
    return err() << "only accepts decode_model \"tq2_0\" (2-bit ternary field) "
                    "or \"tq1_0\" (base-3 ternary); got \""
                 << decodeModel << "\"";
  if (coreLmul.has_value() && *coreLmul != "mf2" && *coreLmul != "m1")
    return err() << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 "
                    "fractional chain) or \"m1\" (the RVV0.7 whole-LMUL chain); "
                    "got \""
                 << *coreLmul << "\"";
  return mlir::success();
}

mlir::LogicalResult RepackGemvTernaryCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackTernaryCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemv_ternary_core",
          getKind(), getDecodeModel(), getIntegerCoreLmul())))
    return mlir::failure();

  if (op->getNumOperands() != 4 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked ternary weight base, the plain block_q8_K "
              "activation base, one !weft_rvv.vl operand, one block_index "
              "induction operand, and one or more per-strip i32 vector results "
              "(one per disjoint strip -- numHalves total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-strip result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-strip combined ternary sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-strip results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise ternary trit-dot core";
  return mlir::success();
}

mlir::LogicalResult RepackGemmTernaryCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackTernaryCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemm_ternary_core",
          getKind(), getDecodeModel(), getIntegerCoreLmul())))
    return mlir::failure();

  if (op->getNumOperands() != 5 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked ternary weight base, the interleaved "
              "block_q8_Kx4 activation base, one !weft_rvv.vl operand, one "
              "block_index induction operand, one strip_row_offset operand, and "
              "one or more per-column i32 vector results (columnsPerPass total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  if (!llvm::isa<mlir::IndexType>(getStripRowOffset().getType()))
    return emitOpError()
           << "requires the strip_row_offset operand to be index-typed (the "
              "runtime strip row offset, region argument 1)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-column result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-column combined ternary sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-column results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise ternary trit-dot core";
  return mlir::success();
}

mlir::LogicalResult UnsignedNibbleXI8ProductOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.unsigned_nibble_x_i8_product keeps source/result "
                "SEW/LMUL/policy on typed vector values and setvl/with_vl, "
                "runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";

    if (!isAllowedWideningProductAttr(attrName))
      return emitOpError()
             << "only accepts generic widening product attributes 'kind' and "
                "'product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "unsigned_nibble_x_i8_product")
    return emitOpError()
           << "currently supports only kind "
              "\"unsigned_nibble_x_i8_product\" for the bounded unsigned-nibble "
              "asymmetric packed-i4 x plain-i8 widening-product typed surface";
  // The q4_1 unsigned-nibble core has a SINGLE m1 rung (no narrow INC-1 anchor):
  // i4m1 weight x i8m1 low/high activation -> i16m2. The unsigned nibble value IS
  // the weight, so there is no offset-binary bias and no codebook gather.
  if (getProductRelation() != "unsigned-nibble-i4m1-x-i8m1x2-to-i16m2")
    return emitOpError()
           << "requires product_relation "
              "\"unsigned-nibble-i4m1-x-i8m1x2-to-i16m2\" (the single m1 "
              "flat-cohort rung) for the bounded asymmetric unsigned-nibble "
              "packed-i4 x plain-i8 widening-product route";

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one UNSIGNED packed-i4 weight operand, two plain-int8 "
              "activation operands, one !weft_rvv.vl operand, and one widened "
              "i16 result";

  if (!isGenericRVVUnsignedIntegerVectorType(
          getWeight().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
    return emitOpError()
           << "requires the packed-i4 weight source vector to be an UNSIGNED i8 "
              "!weft_rvv.vector<ui8, \"m1\"> for the m1 asymmetric "
              "unsigned-nibble packed-i4 x plain-i8 widening-product rung";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getActivationLow().getType(), getRVVSEW8Bits(), getRVVLMULM1()) ||
      !isGenericRVVSignedOrSignlessIntegerVectorType(
          getActivationHigh().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
    return emitOpError()
           << "requires the low and high plain-int8 activation source vectors "
              "to have type !weft_rvv.vector<i8, \"m1\"> for the m1 asymmetric "
              "unsigned-nibble packed-i4 x plain-i8 widening-product rung";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getResult().getType(), getRVVSEW16Bits(), getRVVLMULM2()))
    return emitOpError()
           << "requires result vector to have type "
              "!weft_rvv.vector<i16, \"m2\"> for the m1 asymmetric "
              "unsigned-nibble packed-i4 x plain-i8 widening-product rung";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for asymmetric unsigned-nibble packed-i4 x plain-i8 "
              "widening product";

  return mlir::success();
}

mlir::LogicalResult FiveBitOffsetBinaryXI8ProductOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.five_bit_offset_binary_x_i8_product keeps "
                "source/result SEW/LMUL/policy on typed vector values and "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding control-plane "
                "IR, and rejects deleted local element_count metadata";

    if (!isAllowedWideningProductAttr(attrName))
      return emitOpError()
             << "only accepts generic widening product attributes 'kind' and "
                "'product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "five_bit_offset_binary_x_i8_product")
    return emitOpError()
           << "currently supports only kind "
              "\"five_bit_offset_binary_x_i8_product\" for the bounded five-bit "
              "(nibble+qh) offset-binary x plain-i8 widening-product typed surface";
  // The q5_0 five-bit offset-binary core has a SINGLE m1 rung: i4m1 weight + qh
  // 5th bit x i8m1 low/high activation -> i16m2. DISTINCT from the unsigned-nibble
  // rung -- the qh 5th bit merge and the `-16` offset-binary bias are structural.
  if (getProductRelation() != "five-bit-offset-binary-i4m1-x-i8m1x2-to-i16m2")
    return emitOpError()
           << "requires product_relation "
              "\"five-bit-offset-binary-i4m1-x-i8m1x2-to-i16m2\" (the single m1 "
              "flat-cohort rung) for the bounded five-bit offset-binary packed x "
              "plain-i8 widening-product route";

  if (op->getNumOperands() != 5 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one UNSIGNED packed weight operand, one scalar i32 "
              "qh_source operand, two plain-int8 activation operands, one "
              "!weft_rvv.vl operand, and one widened i16 result";

  if (!isGenericRVVUnsignedIntegerVectorType(
          getWeight().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
    return emitOpError()
           << "requires the packed weight source vector to be an UNSIGNED i8 "
              "!weft_rvv.vector<ui8, \"m1\"> for the m1 five-bit offset-binary "
              "packed x plain-i8 widening-product rung";
  // The qh_source is a SCALAR i32 gate-only token (the block_five_bit_qh_source
  // brick result), NOT a typed vector -- the 5th-bit bytes are re-read from that
  // brick's operand-flow source, so this edge must reject the vector-type checks
  // the weight/activation operands carry.
  if (!getQhSource().getType().isInteger(32))
    return emitOpError()
           << "requires the qh_source operand to be a scalar i32 (the "
              "block_five_bit_qh_source gate-only token), NOT a typed vector";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getActivationLow().getType(), getRVVSEW8Bits(), getRVVLMULM1()) ||
      !isGenericRVVSignedOrSignlessIntegerVectorType(
          getActivationHigh().getType(), getRVVSEW8Bits(), getRVVLMULM1()))
    return emitOpError()
           << "requires the low and high plain-int8 activation source vectors "
              "to have type !weft_rvv.vector<i8, \"m1\"> for the m1 five-bit "
              "offset-binary packed x plain-i8 widening-product rung";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getResult().getType(), getRVVSEW16Bits(), getRVVLMULM2()))
    return emitOpError()
           << "requires result vector to have type "
              "!weft_rvv.vector<i16, \"m2\"> for the m1 five-bit offset-binary "
              "packed x plain-i8 widening-product rung";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for five-bit offset-binary packed x plain-i8 widening "
              "product";

  return mlir::success();
}

mlir::LogicalResult CodebookTableBroadcastOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.codebook_table_broadcast keeps the result SEW/LMUL "
                "on the typed vector value and setvl/with_vl, and rejects "
                "deleted local element_count metadata";
    if (attrName != "codebook" && attrName != "table_symbol")
      return emitOpError()
             << "only accepts the codebook table-broadcast attributes "
                "'codebook' and 'table_symbol'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getCodebook().size() != 16)
    return emitOpError()
           << "requires a 16-entry DenseI8ArrayAttr codebook (the kvalues "
              "lookup range [0,15]); got "
           << getCodebook().size() << " entries";
  if (getTableSymbol().trim().empty())
    return emitOpError()
           << "requires a non-empty table_symbol naming the structured const "
              "codebook decl";

  if (op->getNumOperands() != 0 || op->getNumResults() != 1)
    return emitOpError()
           << "consumes no SSA operands (the table is a compile-time constant) "
              "and produces one i8 LMUL codebook-table vector result";
  auto resultVec = llvm::dyn_cast<VectorType>(getResult().getType());
  if (!resultVec ||
      !isGenericRVVSignedOrSignlessIntegerVectorType(
          getResult().getType(), getRVVSEW8Bits(), resultVec.getLmul()))
    return emitOpError()
           << "requires a signed/signless i8 LMUL !weft_rvv.vector result for "
              "the broadcast codebook table register";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the codebook table broadcast";

  return mlir::success();
}

mlir::LogicalResult CodebookGatherXI8ProductOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.codebook_gather_x_i8_product keeps source/result "
                "SEW/LMUL/policy on typed vector values and setvl/with_vl, "
                "runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";
    if (!isAllowedWideningProductAttr(attrName))
      return emitOpError()
             << "only accepts generic widening product attributes 'kind' and "
                "'product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "signed_codebook_gather_x_i8_product")
    return emitOpError()
           << "currently supports only kind "
              "\"signed_codebook_gather_x_i8_product\" for the bounded "
              "codebook-gather packed-i4 x plain-i8 widening-product surface";
  if (getProductRelation() != "codebook-gather-i8-x-i8x2-to-i16")
    return emitOpError()
           << "requires product_relation \"codebook-gather-i8-x-i8x2-to-i16\" "
              "for the bounded codebook-gather packed-i4 x plain-i8 "
              "widening-product route";

  if (op->getNumOperands() != 5 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one UNSIGNED i8 LMUL packed-i4 weight operand, two "
              "SIGNED i8 LMUL plain-int8 activation operands, one SIGNED i8 LMUL "
              "codebook-table operand, one !weft_rvv.vl operand, and one i16 "
              "LMUL result";

  // The codebook i8 source LMUL is the VLEN-capability anchor (m1 at VLEN128,
  // mf2 at VLEN256): read it off the weight vector and DERIVE the widened i16
  // product LMUL (the genuine flip), instead of pinning a single LMUL.
  auto weightVec = llvm::dyn_cast<VectorType>(getWeight().getType());
  if (!weightVec)
    return emitOpError() << "requires a typed !weft_rvv.vector weight operand";
  llvm::StringRef srcLMUL = weightVec.getLmul();
  llvm::StringRef productLMUL =
      weft::plugin::rvv::getRVVNextWiderLMUL(srcLMUL);
  if (productLMUL.empty())
    return emitOpError() << "no wider i16 product LMUL rung for the codebook i8 "
                            "source anchor '"
                         << srcLMUL << "'";

  if (!isGenericRVVUnsignedIntegerVectorType(getWeight().getType(),
                                             getRVVSEW8Bits(), srcLMUL))
    return emitOpError()
           << "requires the packed-i4 weight source vector to be an UNSIGNED i8 "
              "LMUL !weft_rvv.vector (the gather index lanes run on the u8 lane)";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getActivationLow().getType(), getRVVSEW8Bits(), srcLMUL) ||
      !isGenericRVVSignedOrSignlessIntegerVectorType(
          getActivationHigh().getType(), getRVVSEW8Bits(), srcLMUL))
    return emitOpError()
           << "requires the low and high plain-int8 activation source vectors "
              "to be signed/signless i8 LMUL !weft_rvv.vector matching the "
              "weight anchor '"
           << srcLMUL << "'";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getTable().getType(), getRVVSEW8Bits(), srcLMUL))
    return emitOpError()
           << "requires the codebook-table source vector to be a signed/"
              "signless i8 LMUL !weft_rvv.vector matching the weight anchor '"
           << srcLMUL << "'";
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getResult().getType(), getRVVSEW16Bits(), productLMUL))
    return emitOpError()
           << "requires the result vector to be a signed/signless i16 LMUL "
              "!weft_rvv.vector at the widened product anchor '"
           << productLMUL << "'";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for codebook-gather packed-i4 x plain-i8 widening "
              "product";

  return mlir::success();
}

//===----------------------------------------------------------------------===//
// TunableScheduleOpInterface implementations.
//
// The interface is family-neutral (it returns ONLY primitives); the kernel key
// is the same string each formula keys its tuning record on.
// hasCompleteSchedule() reports structural field completeness only; candidate
// construction, legality and selection remain plugin-local (no dialect -> plugin
// cycle).
//===----------------------------------------------------------------------===//

llvm::StringRef GgmlBlockDotQ40Q80Op::getScheduleKernelKey() { return "q4_0"; }
bool GgmlBlockDotQ40Q80Op::hasCompleteSchedule() {
  return static_cast<bool>(getIntegerCoreLmul()) &&
         static_cast<bool>(getMultiBlockFactor()) &&
         static_cast<bool>(getStripElision());
}

// tq2_0 (the 2-bit TERNARY class) carries ONLY the integer_core_lmul knob (no
// multi_block_factor / strip_elision -- the fused ternary dot is ALWAYS one
// 32-lane plane body). Its 32-element 2-bit plane straddles m1's i8 VLMAX
// boundary between VLEN128/256 (like q1_0 / q8_0), so the gearbox stamps "m2" at
// VLEN128 / "m1" at VLEN256. KEPT across the tq2_0 flip: the monolith op RETIRED,
// but the Win-A gearbox moved verbatim onto the constructed FUSED 2-bit TERNARY
// integer-core brick (SAME kernel key "tq2_0", so the unified autotuner -- which
// dyn_casts TunableScheduleOpInterface, not op-type -- stamps the SAME m2->m1
// selection onto the brick without any registry change).
llvm::StringRef GgmlBlockDotTQ20Q8KTernaryCoreOp::getScheduleKernelKey() {
  return "tq2_0";
}
bool GgmlBlockDotTQ20Q8KTernaryCoreOp::hasCompleteSchedule() {
  return static_cast<bool>(getIntegerCoreLmul()) &&
         static_cast<bool>(getMinimumVlen());
}

// tq1_0 (the BASE-3 TERNARY class) carries ONLY the integer_core_lmul knob; here
// it tunes the integer DOT (section B) over the element-ordered aux8[256] (the
// base-3 unpack section A is unchanged). The flat 256-element dot widens to
// 32-lane strips whose anchor straddles m1's i8 VLMAX boundary between VLEN128/256
// (like q1_0 / tq2_0), so the gearbox stamps "m2" at VLEN128 / "m1" at VLEN256.
// KEPT across the tq1_0 flip: the monolith op RETIRED, but the Win-A gearbox moved
// verbatim onto the constructed BASE-3 TERNARY integer-core brick (SAME kernel key
// "tq1_0", so the unified autotuner -- which dyn_casts TunableScheduleOpInterface,
// not op-type -- stamps the SAME m2->m1 selection onto the brick without any
// registry change).
// q1_0 (the BINARY {-1,+1}-sign class) carries ONLY the integer_core_lmul knob;
// here it tunes the 32-lane binary sign-decode -> vwredsum dot over each of the
// four q8_0 sub-blocks. The 32-element sub-block straddles m1's i8 VLMAX boundary
// between VLEN128/256 (like q8_0 / tq1_0 / tq2_0), so the gearbox stamps "m2" at
// VLEN128 / "m1" at VLEN256. The constructed binary-sign integer-core brick is
// the sole q1_0 schedule consumer (kernel key "q1_0"); the unified autotuner
// reaches it through TunableScheduleOpInterface rather than an op-type branch.
llvm::StringRef GgmlBlockDotQ10Q80BinarySignCoreOp::getScheduleKernelKey() {
  return "q1_0";
}
bool GgmlBlockDotQ10Q80BinarySignCoreOp::hasCompleteSchedule() {
  return static_cast<bool>(getIntegerCoreLmul()) &&
         static_cast<bool>(getMinimumVlen());
}

// The CODEBOOK-class block-dots (FP4 family). They carry the SAME bounded shape
// knobs the Family-A siblings do (integer_core_lmul / multi_block_factor /
// strip_elision), so the SAME pin predicate applies; their gearbox descriptor
// enumerates the codebook anchor set {m1, mf2} (the i8 gather VLMAX>=16 fact).
llvm::StringRef GgmlBlockDotMXFP4Q80Op::getScheduleKernelKey() {
  return "mxfp4";
}
bool GgmlBlockDotMXFP4Q80Op::hasCompleteSchedule() {
  return static_cast<bool>(getIntegerCoreLmul()) &&
         static_cast<bool>(getMultiBlockFactor()) &&
         static_cast<bool>(getStripElision()) &&
         static_cast<bool>(getMinimumVlen());
}

llvm::StringRef GgmlGemmQ40Q80Op::getScheduleKernelKey() {
  return "q4_0_q8_0_gemm";
}
bool GgmlGemmQ40Q80Op::hasCompleteSchedule() {
  return getActivationCols().has_value();
}

// iq2_xxs (the GRID-codebook class) carries ONLY the integer_core_lmul knob (no
// multi_block_factor / strip_elision -- the grid+sign vluxei16 gather + dot is
// ALWAYS one 32-lane sub-block body). The 4 u64 grid entries gather as i64<anchor>
// (4 entries = 32 i8 = the 32-lane sub-block); a single i64 is 8 bytes so the
// 4-entry gather needs an i64 anchor whose VLMAX reaches 4 (i8 view spans 32),
// which straddles m1's i8 VLMAX boundary between VLEN128/256 (like tq2_0 / q1_0),
// so the gearbox stamps "m2" at VLEN128 / "m1" at VLEN256 (ggml's _vl256 shape).
// KEPT across the iq2_xxs flip: the monolith op RETIRED, but the Win-A gearbox moved
// verbatim onto the constructed GRID-of-8 grid-core brick (SAME kernel key "iq2_xxs",
// so the unified autotuner -- which dyn_casts TunableScheduleOpInterface, not op-type --
// stamps the SAME m2->m1 selection onto the brick without any registry change).
llvm::StringRef GgmlBlockDotIQ2XXSQ8KGridCoreOp::getScheduleKernelKey() {
  return "iq2_xxs";
}
bool GgmlBlockDotIQ2XXSQ8KGridCoreOp::hasCompleteSchedule() {
  return static_cast<bool>(getIntegerCoreLmul()) &&
         static_cast<bool>(getMinimumVlen());
}

mlir::LogicalResult GgmlBlockDotQ40Q80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16 scale model, and the block-format structural facts. Anything else
  // -- a forbidden local element_count/SEW/LMUL/policy attr, or an unexpected
  // name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    // The bounded block-format facts and final schedule fields are the complete
    // executable surface. Formula provenance is transient and is not accepted as
    // an IR-side authority.
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" || name == "quant_byte_offset" ||
           name == "activation_high_byte_offset" ||
           name == "integer_core_lmul" || name == "multi_block_factor" ||
           name == "strip_elision" || name == "minimum_vlen" ||
           name == "weft_rvv.flat_decode_primitive" ||
           name == "weft_rvv.flat_fold_model" ||
           name == "weft_rvv.flat_block_length" ||
           name == "weft_rvv.flat_activation_quant_byte_offset" ||
           name == "weft_rvv.flat_weight_scale_source" ||
           name == "weft_rvv.flat_codebook_table_name" ||
           name == "weft_rvv.flat_body_family" ||
           name == "weft_rvv.flat_offset_bias";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_0_q8_0_block_dot keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded block dot-product attributes 'kind', "
                "'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'quant_byte_offset', and "
                "'activation_high_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q4_0_q8_0_block_dot")
    return emitOpError()
           << "currently supports only kind \"ggml_q4_0_q8_0_block_dot\" for "
              "the bounded ggml Q4_0 x Q8_0 block dot-product typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y\" for the "
              "ggml Q4_0 x Q8_0 block dot-product route";
  // ggml's externally-defined block format (ggml-common.h): QK8_0 == 32,
  // block_q4_0 stride 18, block_q8_0 stride 34, quants at byte offset +2, the
  // q8 high half at +16 within the block payload. Pin them so a malformed
  // typed body cannot lower under the block-dot emission.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_0) for the ggml Q4_0 x "
                            "Q8_0 block dot-product route";
  if (getWeightBlockStride() != 18)
    return emitOpError()
           << "requires weight_block_stride == 18 (sizeof block_q4_0) for the "
              "ggml Q4_0 x Q8_0 block dot-product route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
              "the ggml Q4_0 x Q8_0 block dot-product route";
  if (getQuantByteOffset() != 2)
    return emitOpError()
           << "requires quant_byte_offset == 2 (quants follow the inline fp16 "
              "scale) for the ggml Q4_0 x Q8_0 block dot-product route";
  if (getActivationHighByteOffset() != 16)
    return emitOpError()
           << "requires activation_high_byte_offset == 16 (q8 high half) for "
              "the ggml Q4_0 x Q8_0 block dot-product route";

  // The optional integer-core LMUL is a bounded resource/scheduling fact: the
  // per-block dot-product core anchors at "mf4" (the INC-2a default) or "m1"
  // (the ggml-matching one-vwredsum-per-block anchor). Both are byte-exact; any
  // other spelling is rejected fail-closed (I7).
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul()) {
    if (*coreLmul != "mf4" && *coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf4\" or \"m1\" (the bounded "
                "byte-exact resource anchors for the ggml Q4_0 x Q8_0 block "
                "dot-product integer core); got \""
             << *coreLmul << "\"";
  }

  unsigned scheduleFields = static_cast<bool>(getIntegerCoreLmul()) +
                            static_cast<bool>(getMultiBlockFactor()) +
                            static_cast<bool>(getStripElision());
  if (scheduleFields != 0 && scheduleFields != 3)
    return emitOpError()
           << "requires integer_core_lmul, multi_block_factor, and "
              "strip_elision to be all absent or all present";

  // The optional multi_block_factor is a bounded resource/scheduling shape knob:
  // the outer block loop processes 1 (default), 2, or 4 blocks per iteration. It
  // is byte-exact (the per-block fp32 folds stay in strict ascending order; only
  // the independent integer cores overlap). Any other count is rejected
  // fail-closed (I7).
  if (std::optional<std::int64_t> multiBlockFactor = getMultiBlockFactor())
    if (*multiBlockFactor != 1 && *multiBlockFactor != 2 &&
        *multiBlockFactor != 4)
      return emitOpError()
             << "only accepts multi_block_factor 1, 2, or 4 (the bounded "
                "byte-exact block-unroll factors for the ggml Q4_0 x Q8_0 block "
                "dot-product outer loop); got "
             << *multiBlockFactor;

  // The optional strip_elision is a bounded resource/scheduling shape knob: the
  // inner half-block strip loop is kept ("robust", default -- correct at any
  // VLEN) or elided ("elided" -- a single vsetvl_e8m1(16) + one vwredsum per
  // half-block, correct ONLY at VLEN >= 128). Any other spelling is rejected
  // fail-closed (I7).
  if (std::optional<llvm::StringRef> stripElision = getStripElision()) {
    if (*stripElision != "robust" && *stripElision != "elided")
      return emitOpError()
             << "only accepts strip_elision \"robust\" or \"elided\" (the "
                "bounded inner-strip-loop shape knobs for the ggml Q4_0 x Q8_0 "
                "block dot-product); got \""
             << *stripElision << "\"";
    // The elided form drops the inner strip loop and emits a single
    // vsetvl_e8m1(16) per half-block; it is correct only when the integer core
    // anchors at m1 (mf4's vsetvl_e32m1 VLMAX is 4 at VLEN=128, which would
    // silently drop 12 of the 16 nibble bytes). Reject the silently-wrong
    // combination fail-closed (I7) so the autotuner cannot request it.
    if (*stripElision == "elided" && *getIntegerCoreLmul() != "m1")
      return emitOpError()
             << "strip_elision \"elided\" requires integer_core_lmul \"m1\" "
                "(the single-vsetvl_e8m1(16) half-block cover is correct only at "
                "the m1 anchor; the mf4 anchor's vsetvl_e32m1 VLMAX would drop "
                "12 of 16 nibble bytes)";
  }

  if (op->getNumOperands() != 5 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one output pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, and one i32 LMUL m1 result";

  // The three buffer operands and the element count are runtime ABI values; the
  // weight/activation bases address the AoS byte arrays as const uint8_t *, the
  // output is a float *, and the element count carries n. Their C types pin the
  // ggml ABI byte layout the emission depends on.
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_0 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 byte "
              "array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q4_0 x Q8_0 block dot-product route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q4_0 x Q8_0 block dot-product";

  return mlir::success();
}

mlir::LogicalResult GgmlQuantContractionOp::verify() {
  mlir::Operation *op = getOperation();

  // The abstract option-2 stage-A contraction request carries ONLY its bounded
  // WHAT attrs (I4): an OPTIONAL quant format LABEL, the dual-fp16 scale model,
  // the M-regime, the PLAIN weight-layout commitment, the plain block-format byte
  // facts, the STRUCTURED OPPONENT FACTS that drive routing
  // (opponent_vlen_native_floor / block_dot_compute_heavy /
  // block_dot_memory_bound), and an optional
  // advisory min_vlen capability snapshot. Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, an unexpected name, or any REPACK-only
  // layout fact (weight_interleave / half_lanes / the x16 stride 288) -- is
  // rejected fail-closed (I7). The repack-only facts are deliberately absent:
  // this op is PRE-weight-layout-commitment.
  auto isAllowedQuantContractionAttr = [](llvm::StringRef name) {
    return name == "quant" || name == "scale_model" || name == "m_regime" ||
           name == "qk" || name == "weight_layout" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" || name == "quant_byte_offset" ||
           name == "activation_high_byte_offset" ||
           name == "opponent_vlen_native_floor" ||
           name == "block_dot_compute_heavy" ||
           name == "block_dot_memory_bound" || name == "min_vlen";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.quant_contraction keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/nc/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedQuantContractionAttr(attrName))
      return emitOpError()
             << "only accepts the bounded abstract contraction attributes "
                "'quant', 'scale_model', 'm_regime', 'qk', 'weight_layout', "
                "'weight_block_stride', 'activation_block_stride', "
                "'quant_byte_offset', 'activation_high_byte_offset', the "
                "structured opponent facts 'opponent_vlen_native_floor' / "
                "'block_dot_compute_heavy' / 'block_dot_memory_bound', and the "
                "advisory 'min_vlen'; "
                "unexpected attribute '"
             << attr.getName()
             << "' (the repack-only weight_interleave / half_lanes / x16 layout "
                "facts are a stage-C materialization and may not be carried "
                "here)";
  }

  // weight_layout is PINNED "plain" fail-closed: this op is
  // pre-weight-layout-commitment, so it may never carry the repacked "x16"
  // layout (that is a stage-C plain->x16 materialization, not an input fact).
  if (getWeightLayout() != "plain")
    return emitOpError()
           << "requires weight_layout \"plain\" (the abstract quant_contraction "
              "op is pre-weight-layout-commitment and takes un-repacked plain "
              "weights; the repacked \"x16\" layout is a stage-C materialization "
              "the compiler drives, never an input fact); got \""
           << getWeightLayout() << "\"";

  // The committed WHAT axes. `quant` is now an OPTIONAL, purely human-readable
  // format LABEL (a table-lookup / provenance token) -- the verifier does NOT
  // require it and NEVER routes on it: the repack-vs-block-dot decision is driven
  // by the structured opponent facts (opponent_vlen_native_floor /
  // block_dot_compute_heavy / block_dot_memory_bound) plus the derived capability
  // VLEN, so an op with the
  // facts but NO `quant` label lowers to the IDENTICAL concrete region. The
  // decode FAMILY of a request is pinned STRUCTURALLY by the committed
  // `scale_model` WHAT (NOT the label) plus the plain block-format facts below.
  // THREE decode families are accepted (all plain, all fail-closed pinned):
  //   * q4_0      -- scale_model "dual-fp16-per-block-d_x.d_y" (the flat QK8_0
  //                  dual-fp16 offset-binary nibble contraction).
  //   * ternary   -- scale_model
  //     (tq2_0)      "superblock-d.fp16-single-scale-2bit-ternary-nomin" (the
  //                  tq2_0 BitNet-class 2-bit trit super-block, single fp16 scale,
  //                  LINEAR no-min). Its repack-SELECTED lowering CONSTRUCTS the
  //                  ternary typed_repack_gem{v,m}_loop_body region.
  //   * ternary   -- scale_model
  //     (tq1_0)      "superblock-d.fp16-single-scale-base3-ternary-nomin" (the
  //                  tq1_0 lowest-bit BASE-3 trit super-block, single fp16 scale,
  //                  LINEAR no-min; the SAME ternary loop-body region + core brick
  //                  as tq2_0, differing ONLY in the base-3 two-plane WEIGHT
  //                  DECODE, keyed off the core brick's decode_model "tq1_0").
  //   * K-quant   -- scale_model "superblock-d.dmin-fp16-plus-bsums-min-8-subblocks"
  //     (q4_K)       (the q4_K super-block dual d/dmin fp16 scale + 6-bit
  //                  per-sub-block scale/min + activation bsums-min, 8 sub-blocks).
  //                  Its repack-SELECTED lowering CONSTRUCTS the K-quant
  //                  typed_repack_gem{v,m}_loop_body region (fold_model
  //                  "kquant_dmin_bsums_min") carrying the repack_gem{v,m}_kquant_core
  //                  brick (decode_model "q4_K").
  bool isQ40Family = getScaleModel() == "dual-fp16-per-block-d_x.d_y";
  // q4_1 -- scale_model "dual-fp16-per-block-d_x.d_y-plus-min" (the asymmetric flat
  // QK8_1 nibble contraction: the q4_0 dual-fp16 d_x*d_y scale PLUS a single
  // per-block MIN term m_x*s_y, RAW unsigned nibbles [0,15]). Its repack-SELECTED
  // lowering CONSTRUCTS the SAME typed_repack_gem{v,m}_loop_body region as q4_0
  // (fold_model "lane_wise_vector_scale_min") via the SHARED q4_0 bricks -- the core
  // stamping weight_nibble_unsigned + the fold stamping the single MIN offset pair.
  bool isQ41Family =
      getScaleModel() == "dual-fp16-per-block-d_x.d_y-plus-min";
  // q5_0 -- scale_model "dual-fp16-per-block-d_x.d_y-five-bit" (the flat QK8_0
  // FIVE-bit nibble+qh contraction: the SAME q4_0 dual-fp16 d_x*d_y scale + plain
  // q8_0 activation, NO min, but each weight is `((nibble) | (qh_bit << 4)) - 16`
  // -- a RAW unsigned nibble peel OR the transposed qh 5th bit, centered by -16).
  // Its repack-SELECTED lowering CONSTRUCTS the SAME typed_repack_gem{v,m}_loop_body
  // region as q4_0 (fold_model "lane_wise_vector_scale") via the SHARED q4_0 core +
  // fold bricks -- the core stamping weight_nibble_unsigned + weight_qh_byte_offset
  // + weight_offset_bias (the 5th-bit decode leaf); the d-only fold is q4_0's WHOLE.
  bool isQ50Family =
      getScaleModel() == "dual-fp16-per-block-d_x.d_y-five-bit";
  // q5_1 -- scale_model "dual-fp16-per-block-d_x.d_y-plus-min-five-bit" (the
  // asymmetric flat QK8_1 FIVE-bit nibble+qh contraction: the UNION of q5_0's
  // 5th-bit qh decode and q4_1's single per-block MIN fold. Each weight is
  // `(nibble) | (qh_bit << 4)` UNSIGNED in [0,31] -- NO offset-binary -16 (unlike
  // q5_0); the fold is q4_1's dual-fp16 d_x*d_y PLUS the m_x*s_y min term over a
  // block_q8_1 activation). Its repack-SELECTED lowering CONSTRUCTS the SAME
  // typed_repack_gem{v,m}_loop_body region as q4_1 (fold_model
  // "lane_wise_vector_scale_min") via the SHARED q4_0 core + fold bricks -- the core
  // stamping weight_nibble_unsigned + weight_qh_byte_offset (NO bias) + the fold
  // stamping the single MIN offset pair.
  bool isQ51Family =
      getScaleModel() == "dual-fp16-per-block-d_x.d_y-plus-min-five-bit";
  // q8_0 -- scale_model "dual-fp16-per-block-d_x.d_y-full-i8" (the flat QK8_0
  // FULL-int8 contraction: the SAME q4_0 dual-fp16 d_x*d_y scale + plain q8_0
  // activation, NO min, but each weight is a FULL signed int8 -- NO nibble unpack,
  // qk=32 positions per block, i32 in-block accumulation). Its repack-SELECTED
  // lowering CONSTRUCTS the SAME typed_repack_gem{v,m}_loop_body region as q4_0
  // (fold_model "lane_wise_vector_scale", the d-only fold WHOLE) via the SHARED
  // dual-fp16 fold brick + the q8_0 full-i8 CORE brick variant (the core stamping
  // weight_full_i8: vle8 i8 + vwmul/vwadd_wv i32, NO nibble decode). The SIMPLEST
  // flat family (no nibble unpack, no qh, no offset, no min).
  bool isQ80Family =
      getScaleModel() == "dual-fp16-per-block-d_x.d_y-full-i8";
  bool isTernaryTQ20Family =
      getScaleModel() == "superblock-d.fp16-single-scale-2bit-ternary-nomin";
  bool isTernaryTQ10Family =
      getScaleModel() == "superblock-d.fp16-single-scale-base3-ternary-nomin";
  bool isKQuantQ4KFamily =
      getScaleModel() == "superblock-d.dmin-fp16-plus-bsums-min-8-subblocks";
  // K-quant q6_K -- scale_model "superblock-d.fp16-signed8-scale-16-subblocks-6bit-nomin"
  // (the q6_K super-block SINGLE fp16 d + 16 SIGNED int8 scales + 6-bit two-plane
  // offset-binary weight, NO dmin / NO min / NO bsums, 16 sub-blocks). Its
  // repack-SELECTED lowering CONSTRUCTS the K-quant typed_repack_gem{v,m}_loop_body
  // region (fold_model "kquant_single_scale_no_min", decode_model "q6_K").
  bool isKQuantQ6KFamily =
      getScaleModel() == "superblock-d.fp16-signed8-scale-16-subblocks-6bit-nomin";
  // K-quant q2_K -- scale_model "superblock-d.dmin-fp16-plus-bsums-min-16-subblocks-2bit"
  // (the q2_K super-block dual fp16 d/dmin + 4-bit-packed per-sub-block scale/min +
  // activation bsums-min, 2-BIT UNSIGNED weight, 16 sub-blocks). It SHARES the q4_K
  // min FOLD, so its repack-SELECTED lowering CONSTRUCTS the K-quant
  // typed_repack_gem{v,m}_loop_body region (fold_model "kquant_dmin_bsums_min",
  // decode_model "q2_K") -- the min-fold sibling of the q4_K region.
  bool isKQuantQ2KFamily =
      getScaleModel() == "superblock-d.dmin-fp16-plus-bsums-min-16-subblocks-2bit";
  // K-quant q3_K -- scale_model
  // "superblock-d.fp16-signed6-scale-16-subblocks-3bit-subtractive-hmask-nomin" (the
  // q3_K super-block SINGLE fp16 d + 16 SIGNED 6-bit scales + 3-BIT SUBTRACTIVE weight
  // assembled from a 2-bit qs low plane + a 1-bit hmask high plane, NO dmin / NO min /
  // NO bsums, 16 sub-blocks). It SHARES the q6_K no-min FOLD, so its repack-SELECTED
  // lowering CONSTRUCTS the K-quant typed_repack_gem{v,m}_loop_body region (fold_model
  // "kquant_single_scale_no_min", decode_model "q3_K") -- the no-min sibling of the q6_K
  // region.
  bool isKQuantQ3KFamily =
      getScaleModel() ==
      "superblock-d.fp16-signed6-scale-16-subblocks-3bit-subtractive-hmask-nomin";
  // K-quant q5_K -- scale_model "superblock-d.dmin-fp16-plus-bsums-min-8-subblocks-qh5"
  // (the q5_K super-block dual fp16 d/dmin + 6-bit per-sub-block scale/min + activation
  // bsums-min, 5-BIT weight = the q4_K 4-bit nibble PLUS a qh 5th-bit plane, 8 sub-blocks
  // -- the SAME dual-scale + bsums-min layout as q4_K WITH a qh SECOND weight plane). It
  // SHARES the q4_K min FOLD, so its repack-SELECTED lowering CONSTRUCTS the K-quant
  // typed_repack_gem{v,m}_loop_body region (fold_model "kquant_dmin_bsums_min",
  // decode_model "q5_K") -- the min-fold sibling of the q4_K region WITH the qh plane.
  bool isKQuantQ5KFamily =
      getScaleModel() == "superblock-d.dmin-fp16-plus-bsums-min-8-subblocks-qh5";
  // iq4_nl -- scale_model "flat.fp16-single-scale-codebook-nomin" (the flat 32-element
  // NON-LINEAR codebook block: the 4-bit weight nibble is an INDEX into a 16-entry int8
  // codebook, ONE fp16 scale, i32 in-block accumulator, NO min / NO sub-block). Its
  // repack-SELECTED lowering CONSTRUCTS the codebook typed_repack_gem{v,m}_loop_body
  // region (fold_model "codebook_flat_single_scale") carrying the
  // repack_gem{v,m}_codebook_core brick (decode_model "iq4_nl" + the 16-entry codebook);
  // the compiler RECONSTRUCTS the kvalues table (the abstract request carries no codebook).
  bool isCodebookIq4NlFamily =
      getScaleModel() == "flat.fp16-single-scale-codebook-nomin";
  // iq4_xs -- scale_model "superblock.fp16-signed6-scale-codebook-nomin" (the SUPER-BLOCK
  // NON-LINEAR codebook: QK_K=256, the 4-bit weight nibble is an INDEX into the SAME
  // 16-entry int8 codebook iq4_nl uses, PLUS a K-quant-style 6-bit SIGNED per-sub-block
  // scale (scales_l LOW pair + scales_h HIGH 2-bit, biased -32, NO min), ONE fp16 d, 8
  // sub-blocks). Its repack-SELECTED lowering CONSTRUCTS the codebook
  // typed_repack_gem{v,m}_loop_body region (fold_model "codebook_superblock_signed6_no_min")
  // carrying the SHARED repack_gem{v,m}_codebook_core brick (decode_model "iq4_xs" + the
  // 16-entry codebook); the compiler RECONSTRUCTS the kvalues table + the signed-6 scale
  // facts (the abstract request carries no codebook and no scales offsets).
  bool isCodebookIq4XsFamily =
      getScaleModel() == "superblock.fp16-signed6-scale-codebook-nomin";
  // mxfp4 -- scale_model "flat.e8m0-single-scale-codebook-nomin" (the FLAT 32-element
  // DOUBLED-E2M1 fp4 codebook: the 4-bit weight nibble is an INDEX into a 16-entry int8
  // codebook, an E8M0 shared-exponent per-column scale 2^(e-128) reconstructed by bit
  // arithmetic, i32 in-block accumulator, NO min / NO sub-block -- the E8M0 sibling of
  // iq4_nl). Its repack-SELECTED lowering CONSTRUCTS the codebook typed_repack region
  // (fold_model "codebook_flat_e8m0_scale") carrying the SHARED repack_gem{v,m}_codebook_core
  // brick (decode_model "mxfp4" + the 16-entry codebook); the compiler RECONSTRUCTS the
  // kvalues table (the abstract request carries no codebook).
  bool isCodebookMxfp4Family =
      getScaleModel() == "flat.e8m0-single-scale-codebook-nomin";
  // iq2_xxs -- scale_model "superblock-d.fp16-grid-sign-4bit-scale-nomin-eighth" (the
  // SUPER-BLOCK GRID CODEBOOK + SIGN-PLANE: QK_K=256, each (sub-block, group, column) 8-bit
  // grid INDEX selects an 8-byte ENTRY from the FIXED 256-entry iq2xxs_grid, a 7-bit sign
  // SELECTOR gathers a +-1 byte from the DERIVED signs64 plane folded onto the grid, a
  // per-sub-block int8 ls scale [1,31] (NO -32 bias, NO min), ONE fp16 d, a trailing 0.125
  // factor, 8 sub-blocks). Its repack-SELECTED lowering CONSTRUCTS the grid
  // typed_repack_gem{v,m}_loop_body region (fold_model "grid_sign_single_scale_eighth")
  // carrying the repack_gem{v,m}_grid_core brick (decode_model "iq2_xxs"); the compiler
  // RECONSTRUCTS the fixed grid + signs64 planes (the abstract request carries neither).
  bool isGridIq2XxsFamily =
      getScaleModel() == "superblock-d.fp16-grid-sign-4bit-scale-nomin-eighth";
  // iq2_xs / iq2_s -- the DUAL-scale grid siblings of iq2_xxs (dual per-group ls scale;
  // iq2_xs signs64 DERIVED, iq2_s signs256 DIRECT). Same super-block grid-codebook + sign
  // plane; their repack-SELECTED lowering CONSTRUCTS the grid typed_repack region (fold_model
  // "grid_sign_dualscale_eighth") carrying the SAME repack_gem{v,m}_grid_core brick
  // (decode_model "iq2_xs" / "iq2_s"); the compiler RECONSTRUCTS the grid + signs planes.
  bool isGridIq2XsFamily =
      getScaleModel() == "superblock-d.fp16-grid-sign-dualscale-nomin-eighth";
  bool isGridIq2SFamily =
      getScaleModel() == "superblock-d.fp16-grid-explicitsign-dualscale-nomin-eighth";
  // iq1_s (C4a-2) -- the TERNARY-DELTA grid sibling, the first NON-iq2 grid family.
  // Same QK_K=256 super-block + 8-byte grid ENTRY gather, but the 2048-entry
  // iq1s_grid's bytes are ALREADY signed ternary, so there is NO sign plane: the
  // gathered byte IS the weight. Its per-sub-block SINGLE ls and its +-1 delta are
  // both DERIVED from the qh word at repack time, and the delta drives a SECOND
  // integer accumulator over the ACTIVATION bsums. Its repack-SELECTED lowering
  // CONSTRUCTS the grid typed_repack region (fold_model "grid_ternary_delta_eighth")
  // carrying the SAME repack_gem{v,m}_grid_core brick (decode_model "iq1_s"); the
  // compiler RECONSTRUCTS the 2048-entry grid (the abstract request carries none).
  bool isGridIq1SFamily =
      getScaleModel() ==
      "superblock-d.fp16-grid-ternary-delta-singlescale-nomin-eighth";
  // iq1_m (C4a-3) -- iq1_s's ternary-grid sibling: the SAME 2048-entry already-signed
  // ternary grid + 8-byte entry gather + no sign plane, but DUAL ls (the iq2_xs shape)
  // and a PER-GROUP-of-8 +-1 delta (four INDEPENDENT bits per sub-block) whose delta
  // term needs per-8 activation sums -- which block_q8_K's per-SIXTEEN bsums cannot
  // express, so unlike iq1_s it reads NO bsums and sums the group IN-KERNEL. It also
  // carries NO inline d: the fp16 is ASSEMBLED from four nibbles scattered across the
  // scales words at repack time. Its repack-SELECTED lowering CONSTRUCTS the grid
  // typed_repack region (fold_model "grid_ternary_delta_groupsum_eighth") carrying the
  // SAME repack_gem{v,m}_grid_core brick (decode_model "iq1_m"); the compiler
  // RECONSTRUCTS the 2048-entry grid (the abstract request carries none).
  bool isGridIq1MFamily =
      getScaleModel() ==
      "superblock-d.fp16-grid-ternary-delta-groupsum-dualscale-nomin-eighth";
  // iq3_xxs (C4a-4) -- the DUAL-ENTRY grid sibling. The SAME QK_K=256 super-block, the
  // SAME single per-sub-block ls, and the SAME ksigns_iq2xs sign plane as iq2_xxs (ggml's
  // iq3_xxs vec_dot reads that table by name), but its grid is `uint32_t iq3xxs_grid[256]`
  // -- a 4-byte entry covering only HALF an 8-element group, so the decode gathers TWO
  // entries per group with the activation range split, and the store constant is 0.25f
  // rather than 0.125f. Its repack-SELECTED lowering CONSTRUCTS the grid typed_repack
  // region (fold_model "grid_sign_dual_entry_single_scale_quarter") carrying the SAME
  // repack_gem{v,m}_grid_core brick (decode_model "iq3_xxs"); the compiler RECONSTRUCTS
  // the 256-entry uint32 grid + the DERIVED signs64 plane (the abstract request carries
  // neither).
  bool isGridIq3XxsFamily =
      getScaleModel() == "superblock-d.fp16-grid-sign-dual-entry-4bit-scale-nomin-quarter";
  // iq3_s (C4a-5) -- the LAST grid sibling, and the one that resembles iq3_xxs closely
  // enough to share its whole emitter leaf while siding with DIFFERENT siblings on two
  // axes. SAME QK_K=256 super-block, SAME single per-sub-block ls, SAME dual-entry gather
  // (iq3s_grid is `uint32_t[512]`, so a 4-byte entry still covers only half a group). It
  // differs from iq3_xxs in exactly three DATA facts, all read off ggml_vec_dot_iq3_s_q8_K:
  // a 9-bit index assembled from qs plus a qh bit (=> a u16 index strip); an EXPLICIT
  // per-group sign byte carried by the block and tested with kmask_iq2xs, with no
  // ksigns_iq2xs selector (=> iq2_s's DERIVED signs256 plane, not signs64); and `*s = sumf`
  // -- no store constant at all. Its repack-SELECTED lowering CONSTRUCTS the grid
  // typed_repack region (fold_model "grid_sign_dual_entry_single_scale_unit") carrying the
  // SAME repack_gem{v,m}_grid_core brick (decode_model "iq3_s"); the compiler RECONSTRUCTS
  // the 512-entry uint32 grid + the DERIVED signs256 plane (the abstract request carries
  // neither).
  bool isGridIq3SFamily =
      getScaleModel() ==
      "superblock-d.fp16-grid-explicitsign-dual-entry-4bit-scale-nomin-unit";
  if (!isQ40Family && !isQ41Family && !isQ50Family && !isQ51Family &&
      !isQ80Family && !isTernaryTQ20Family &&
      !isTernaryTQ10Family && !isKQuantQ4KFamily && !isKQuantQ6KFamily &&
      !isKQuantQ2KFamily && !isKQuantQ3KFamily && !isKQuantQ5KFamily &&
      !isCodebookIq4NlFamily && !isCodebookIq4XsFamily &&
      !isCodebookMxfp4Family && !isGridIq2XxsFamily &&
      !isGridIq2XsFamily && !isGridIq2SFamily && !isGridIq1SFamily &&
      !isGridIq1MFamily && !isGridIq3XxsFamily && !isGridIq3SFamily)
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y\" (the q4_0 "
              "flat dual-fp16 nibble family), "
              "\"dual-fp16-per-block-d_x.d_y-plus-min\" (the q4_1 flat "
              "dual-fp16 + single-min nibble family), "
              "\"dual-fp16-per-block-d_x.d_y-five-bit\" (the q5_0 flat "
              "dual-fp16 five-bit nibble+qh family), "
              "\"dual-fp16-per-block-d_x.d_y-plus-min-five-bit\" (the q5_1 flat "
              "dual-fp16 + single-min five-bit nibble+qh family), "
              "\"dual-fp16-per-block-d_x.d_y-full-i8\" (the q8_0 flat "
              "dual-fp16 full-int8 family), "
              "\"superblock-d.fp16-single-scale-2bit-ternary-nomin\" (the ternary "
              "tq2_0 2-bit trit super-block family), "
              "\"superblock-d.fp16-single-scale-base3-ternary-nomin\" (the ternary "
              "tq1_0 base-3 trit super-block family), "
              "\"superblock-d.dmin-fp16-plus-bsums-min-8-subblocks\" (the K-quant "
              "q4_K dual-scale + bsums-min super-block family), "
              "\"superblock-d.fp16-signed8-scale-16-subblocks-6bit-nomin\" (the "
              "K-quant q6_K 6-bit two-plane no-min super-block family), or "
              "\"superblock-d.dmin-fp16-plus-bsums-min-16-subblocks-2bit\" (the "
              "K-quant q2_K 2-bit dual-scale + bsums-min super-block family), or "
              "\"superblock-d.fp16-signed6-scale-16-subblocks-3bit-subtractive-"
              "hmask-nomin\" (the K-quant q3_K 3-bit subtractive-hmask no-min "
              "super-block family), or "
              "\"superblock-d.dmin-fp16-plus-bsums-min-8-subblocks-qh5\" (the "
              "K-quant q5_K 5-bit nibble+qh dual-scale + bsums-min super-block "
              "family), or \"flat.fp16-single-scale-codebook-nomin\" (the iq4_nl "
              "flat non-linear 16-entry codebook family), or "
              "\"superblock.fp16-signed6-scale-codebook-nomin\" (the iq4_xs "
              "super-block 16-entry codebook + 6-bit signed sub-block-scale family), or "
              "\"flat.e8m0-single-scale-codebook-nomin\" (the mxfp4 flat 16-entry "
              "doubled-e2m1 codebook + E8M0 shared-exponent scale family), or "
              "\"superblock-d.fp16-grid-sign-4bit-scale-nomin-eighth\" (the iq2_xxs "
              "super-block grid-codebook + sign-plane family), or "
              "\"superblock-d.fp16-grid-sign-dualscale-nomin-eighth\" (the iq2_xs "
              "dual-scale grid-codebook + signs64 sign-plane family), or "
              "\"superblock-d.fp16-grid-explicitsign-dualscale-nomin-eighth\" (the "
              "iq2_s dual-scale grid-codebook + explicit signs256 sign-plane family), or "
              "\"superblock-d.fp16-grid-ternary-delta-singlescale-nomin-eighth\" (the "
              "iq1_s signed-ternary grid-codebook + qh delta-bsum family), or "
              "\"superblock-d.fp16-grid-ternary-delta-groupsum-dualscale-nomin-eighth\" "
              "(the iq1_m signed-ternary grid-codebook + dual-ls + per-GROUP delta "
              "in-kernel-group-sum family), or "
              // C4a-5: the two iq3 rows were MISSING from this list. iq3_xxs has been
              // ACCEPTED since C4a-4 (isGridIq3XxsFamily above) but was never added to
              // the text, so this diagnostic has been under-reporting the legal set --
              // telling a caller with a valid iq3_xxs WHAT that it is illegal and listing
              // an accepted set that does not contain it. Harmless to the GATE (the
              // predicate, not the string, decides) and invisible to lit (no test pins
              // this tail), which is presumably how it survived. Both are listed now.
              "\"superblock-d.fp16-grid-sign-dual-entry-4bit-scale-nomin-quarter\" "
              "(the iq3_xxs dual-entry uint32-grid + signs64 sign-plane family), or "
              "\"superblock-d.fp16-grid-explicitsign-dual-entry-4bit-scale-nomin-unit\" "
              "(the iq3_s dual-entry uint32-grid + explicit signs256 sign-plane family) "
              "for the abstract block-quantized contraction request; got \""
           << getScaleModel() << "\"";
  if (getMRegime() != "decode" && getMRegime() != "prefill")
    return emitOpError()
           << "requires m_regime in {\"decode\", \"prefill\"} (the M==1 GEVM "
              "vs M>>1 GEMM regime) for the abstract block-quantized "
              "contraction request; got \""
           << getMRegime() << "\"";

  // The PLAIN block-format byte facts, pinned per decode family fail-closed (I7)
  // so a malformed body cannot lower under the identity/repack emission.
  if (isQ40Family) {
    // q4_0: QK8_0 == 32, block_q4_0 stride 18, block_q8_0 stride 34, quants at
    // +2, the q8 high half at +16 (pinned IDENTICALLY to the block-dot verifier).
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK8_0) for the abstract q4_0 "
                              "block-quantized contraction request";
    if (getWeightBlockStride() != 18)
      return emitOpError()
             << "requires weight_block_stride == 18 (sizeof block_q4_0, the "
                "PLAIN weight layout) for the abstract q4_0 block-quantized "
                "contraction request";
    if (getActivationBlockStride() != 34)
      return emitOpError()
             << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
                "the abstract q4_0 block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (quants follow the inline fp16 "
                "scale) for the abstract q4_0 block-quantized contraction "
                "request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (q8 high half) for "
                "the abstract q4_0 block-quantized contraction request";
  } else if (isQ41Family) {
    // q4_1: QK8_1 == 32, PLAIN block_q4_1 stride 20 (fp16 d + fp16 m + 16 nibble
    // bytes), PLAIN block_q8_1 stride 36 (fp16 d + fp16 s + 32 int8 quants),
    // quants at +4 (after the inline fp16 d + fp16 m), the q8 high half at +16.
    // The repacked x16 weight (stride 320, nibbles @64, m strip @32) / block_q8_1
    // activation (36 GEVM, 144 GEMM) facts are a stage-C materialization the q4_1
    // lowering derives, never carried here.
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK8_1) for the abstract q4_1 "
                              "block-quantized contraction request";
    if (getWeightBlockStride() != 20)
      return emitOpError()
             << "requires weight_block_stride == 20 (sizeof block_q4_1: fp16 d + "
                "fp16 m + 16 nibble bytes, the PLAIN weight layout) for the "
                "abstract q4_1 block-quantized contraction request";
    if (getActivationBlockStride() != 36)
      return emitOpError()
             << "requires activation_block_stride == 36 (sizeof block_q8_1: fp16 "
                "d + fp16 s + 32 int8 quants) for the abstract q4_1 "
                "block-quantized contraction request";
    if (getQuantByteOffset() != 4)
      return emitOpError()
             << "requires quant_byte_offset == 4 (quants follow the inline fp16 d "
                "+ fp16 m) for the abstract q4_1 block-quantized contraction "
                "request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (q8 high half) for "
                "the abstract q4_1 block-quantized contraction request";
  } else if (isQ50Family) {
    // q5_0: QK5_0 == 32, PLAIN block_q5_0 stride 22 (fp16 d + uint8 qh[4] + 16
    // nibble bytes), PLAIN block_q8_0 stride 34, activation quants at +2, the q8
    // high half at +16. The repacked x16 weight (stride 352, nibbles @32, the
    // transposed qh plane @288) facts are a stage-C materialization the q5_0
    // lowering derives, never carried here.
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK5_0) for the abstract q5_0 "
                              "block-quantized contraction request";
    if (getWeightBlockStride() != 22)
      return emitOpError()
             << "requires weight_block_stride == 22 (sizeof block_q5_0: fp16 d + "
                "uint8 qh[4] + 16 nibble bytes, the PLAIN weight layout) for the "
                "abstract q5_0 block-quantized contraction request";
    if (getActivationBlockStride() != 34)
      return emitOpError()
             << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
                "the abstract q5_0 block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (block_q8_0 quants follow the "
                "inline fp16 scale) for the abstract q5_0 block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (q8 high half) for "
                "the abstract q5_0 block-quantized contraction request";
  } else if (isQ51Family) {
    // q5_1: QK5_1 == 32, PLAIN block_q5_1 stride 24 (fp16 d + fp16 m + uint8 qh[4]
    // + 16 nibble bytes), PLAIN block_q8_1 stride 36 (fp16 d + fp16 s + 32 int8
    // quants), activation quants at +4 (after the inline fp16 d + fp16 s), the q8
    // high half at +16. The repacked x16 weight (stride 384, nibbles @64, m strip
    // @32, the transposed qh plane @320) / block_q8_1 activation (36 GEVM, 144 GEMM)
    // facts are a stage-C materialization the q5_1 lowering derives, never carried
    // here.
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK5_1) for the abstract q5_1 "
                              "block-quantized contraction request";
    if (getWeightBlockStride() != 24)
      return emitOpError()
             << "requires weight_block_stride == 24 (sizeof block_q5_1: fp16 d + "
                "fp16 m + uint8 qh[4] + 16 nibble bytes, the PLAIN weight layout) "
                "for the abstract q5_1 block-quantized contraction request";
    if (getActivationBlockStride() != 36)
      return emitOpError()
             << "requires activation_block_stride == 36 (sizeof block_q8_1: fp16 "
                "d + fp16 s + 32 int8 quants) for the abstract q5_1 "
                "block-quantized contraction request";
    if (getQuantByteOffset() != 4)
      return emitOpError()
             << "requires quant_byte_offset == 4 (block_q8_1 quants follow the "
                "inline fp16 d + fp16 s) for the abstract q5_1 block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (q8 high half) for "
                "the abstract q5_1 block-quantized contraction request";
  } else if (isQ80Family) {
    // q8_0: QK8_0 == 32, PLAIN block_q8_0 weight stride 34 (fp16 d + 32 int8
    // quants -- the weight is itself a block_q8_0), PLAIN block_q8_0 activation
    // stride 34, quants at +2 (after the inline fp16 scale), the q8 high half at
    // +16. The repacked x16 weight (stride 544, FULL int8 quants @32) / block_q8_0
    // activation (34 GEVM, interleaved block_q8_0x4 136 GEMM) facts are a stage-C
    // materialization the q8_0 lowering derives, never carried here.
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK8_0) for the abstract q8_0 "
                              "block-quantized contraction request";
    if (getWeightBlockStride() != 34)
      return emitOpError()
             << "requires weight_block_stride == 34 (sizeof block_q8_0: fp16 d + "
                "32 int8 quants, the PLAIN full-int8 weight layout) for the "
                "abstract q8_0 block-quantized contraction request";
    if (getActivationBlockStride() != 34)
      return emitOpError()
             << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
                "the abstract q8_0 block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (block_q8_0 quants follow the "
                "inline fp16 scale) for the abstract q8_0 block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (q8 high half) for "
                "the abstract q8_0 block-quantized contraction request";
  } else if (isTernaryTQ20Family) {
    // ternary tq2_0: QK_K == 256, PLAIN block_tq2_0 weight stride 66 (fp16 d +
    // 64 2-bit quant bytes), PLAIN block_q8_K activation stride 292 (fp32 d + 256
    // int8 quants + 16 int16 bsums), weight quants at +2 (after the inline fp16
    // d). The q8_K activation carries NO packed high half, so
    // activation_high_byte_offset is pinned to the 0 sentinel (unused; the
    // ternary repack lowering RECONSTRUCTS the repacked byte facts). The repacked
    // x16 weight (stride 1056) / q8_K activation (292 GEVM, 1168 GEMM) facts are
    // a stage-C materialization the lowering derives, never carried here.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "ternary tq2_0 block-quantized contraction request";
    if (getWeightBlockStride() != 66)
      return emitOpError()
             << "requires weight_block_stride == 66 (sizeof block_tq2_0: fp16 d "
                "+ 64 2-bit quant bytes, the PLAIN ternary weight layout) for "
                "the abstract ternary tq2_0 block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: "
                "fp32 d + 256 int8 quants + 16 int16 bsums) for the abstract "
                "ternary tq2_0 block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the ternary trit quants follow "
                "the inline fp16 d) for the abstract ternary tq2_0 "
                "block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "ternary tq2_0 block-quantized contraction request";
  } else if (isTernaryTQ10Family) {
    // ternary tq1_0: QK_K == 256, PLAIN block_tq1_0 weight stride 54 (48 qs
    // base-3 bytes + 4 qh base-3 bytes + the fp16 d at the END, ggml's block_tq1_0
    // layout), PLAIN block_q8_K activation stride 292 (fp32 d + 256 int8 quants +
    // 16 int16 bsums). The base-3 qs plane starts at byte +0 (the fp16 d trails at
    // +52, so quant_byte_offset is pinned to 0), and the q8_K activation carries NO
    // packed high half (activation_high_byte_offset == 0 sentinel, unused). The
    // repacked x16 weight (stride 864, qs at +32, qh at +800) / q8_K activation
    // (292 GEVM, 1168 GEMM) facts are a stage-C materialization the lowering
    // derives, never carried here.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "ternary tq1_0 block-quantized contraction request";
    if (getWeightBlockStride() != 54)
      return emitOpError()
             << "requires weight_block_stride == 54 (sizeof block_tq1_0: 48 qs "
                "base-3 bytes + 4 qh base-3 bytes + fp16 d, the PLAIN base-3 "
                "ternary weight layout) for the abstract ternary tq1_0 "
                "block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: "
                "fp32 d + 256 int8 quants + 16 int16 bsums) for the abstract "
                "ternary tq1_0 block-quantized contraction request";
    if (getQuantByteOffset() != 0)
      return emitOpError()
             << "requires quant_byte_offset == 0 (the base-3 qs plane leads the "
                "block; the fp16 d trails) for the abstract ternary tq1_0 "
                "block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "ternary tq1_0 block-quantized contraction request";
  } else if (isKQuantQ4KFamily) {
    // K-quant q4_K: QK_K == 256, PLAIN block_q4_K weight stride 144 (fp16 d + fp16
    // dmin + 12 K_SCALE_SIZE 6-bit scales/mins bytes + 128 nibble bytes, ggml's
    // block_q4_K), PLAIN block_q8_K activation stride 292 (fp32 d + 256 int8 quants
    // + 16 int16 bsums). The plain nibbles start at +16 (after the 2 d + 2 dmin + 12
    // scales), and the q8_K activation carries NO packed high half
    // (activation_high_byte_offset == 0 sentinel, unused). The repacked x16 weight
    // (stride 2304, nibbles @256, dmin @32, 6-bit scales @64) / q8_K activation (292
    // GEVM, 1168 GEMM) facts are a stage-C materialization the lowering RECONSTRUCTS
    // from the K-quant decode facts, never carried here.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "K-quant q4_K block-quantized contraction request";
    if (getWeightBlockStride() != 144)
      return emitOpError()
             << "requires weight_block_stride == 144 (sizeof block_q4_K: fp16 d + "
                "fp16 dmin + 12 6-bit scales/mins bytes + 128 nibble bytes, the "
                "PLAIN K-quant weight layout) for the abstract K-quant q4_K "
                "block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 "
                "d + 256 int8 quants + 16 int16 bsums) for the abstract K-quant "
                "q4_K block-quantized contraction request";
    if (getQuantByteOffset() != 16)
      return emitOpError()
             << "requires quant_byte_offset == 16 (the plain q4_K nibbles follow "
                "the fp16 d + fp16 dmin + 12 scales bytes) for the abstract "
                "K-quant q4_K block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "K-quant q4_K block-quantized contraction request";
  } else if (isKQuantQ6KFamily) {
    // K-quant q6_K: QK_K == 256, PLAIN block_q6_K weight stride 210 (128 ql
    // low-4-bit bytes + 64 qh high-2-bit bytes + 16 SIGNED int8 scales + fp16 d,
    // ggml's block_q6_K -- ql@0, qh@128, scales@192, d@208), PLAIN block_q8_K
    // activation stride 292 (fp32 d + 256 int8 quants + 16 int16 bsums; q6_K reads
    // NO bsums). The plain ql plane LEADS the block (quant_byte_offset == 0), and the
    // q8_K activation carries NO packed high half (activation_high_byte_offset == 0
    // sentinel, unused). The repacked x16 weight (stride 3360, ql @1312, qh @288,
    // signed scales @32) / q8_K activation (292/4 GEVM, 1168/16 GEMM) facts are a
    // stage-C materialization the lowering RECONSTRUCTS from the q6_K decode facts.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "K-quant q6_K block-quantized contraction request";
    if (getWeightBlockStride() != 210)
      return emitOpError()
             << "requires weight_block_stride == 210 (sizeof block_q6_K: 128 ql "
                "low-4-bit + 64 qh high-2-bit + 16 signed int8 scales + fp16 d, the "
                "PLAIN K-quant weight layout) for the abstract K-quant q6_K "
                "block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 "
                "d + 256 int8 quants + 16 int16 bsums) for the abstract K-quant "
                "q6_K block-quantized contraction request";
    if (getQuantByteOffset() != 0)
      return emitOpError()
             << "requires quant_byte_offset == 0 (the plain q6_K ql low-4-bit plane "
                "leads the block; qh/scales/d trail) for the abstract K-quant q6_K "
                "block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "K-quant q6_K block-quantized contraction request";
  } else if (isKQuantQ2KFamily) {
    // K-quant q2_K: QK_K == 256, PLAIN block_q2_K weight stride 84 (16 packed 4-bit
    // scale/min bytes + 64 2-bit quant bytes + fp16 d + fp16 dmin, ggml's block_q2_K
    // -- scales@0, qs@16, d@80, dmin@82), PLAIN block_q8_K activation stride 292
    // (fp32 d + 256 int8 quants + 16 int16 bsums). The plain 2-bit qs quants start at
    // +16 (after the 16 packed scale/min bytes), and the q8_K activation carries NO
    // packed high half (activation_high_byte_offset == 0 sentinel, unused). The
    // repacked x16 weight (stride 1344, qs @320, dmin @32, packed scale/min @64) /
    // q8_K activation (292/4/260 GEVM, 1168/16/1040 GEMM) facts are a stage-C
    // materialization the lowering RECONSTRUCTS from the q2_K decode facts.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "K-quant q2_K block-quantized contraction request";
    if (getWeightBlockStride() != 84)
      return emitOpError()
             << "requires weight_block_stride == 84 (sizeof block_q2_K: 16 packed "
                "4-bit scale/min bytes + 64 2-bit quant bytes + fp16 d + fp16 dmin, "
                "the PLAIN K-quant weight layout) for the abstract K-quant q2_K "
                "block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 "
                "d + 256 int8 quants + 16 int16 bsums) for the abstract K-quant "
                "q2_K block-quantized contraction request";
    if (getQuantByteOffset() != 16)
      return emitOpError()
             << "requires quant_byte_offset == 16 (the plain q2_K 2-bit quants "
                "follow the 16 packed 4-bit scale/min bytes) for the abstract "
                "K-quant q2_K block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "K-quant q2_K block-quantized contraction request";
  } else if (isKQuantQ3KFamily) {
    // K-quant q3_K: QK_K == 256, PLAIN block_q3_K weight stride 110 (32 hmask high-bit
    // bytes + 64 qs low-2-bit bytes + 12 6-bit-packed scales + fp16 d, ggml's block_q3_K
    // -- hmask@0, qs@32, scales@96, d@108), PLAIN block_q8_K activation stride 292 (fp32
    // d + 256 int8 quants + 16 int16 bsums; q3_K reads NO bsums). The plain hmask plane
    // LEADS the block (quant_byte_offset == 0), and the q8_K activation carries NO packed
    // high half (activation_high_byte_offset == 0 sentinel, unused). The repacked x16
    // weight (stride 1824, qs @800, hmask @288 [the SHARED qh slot], signed scales @32) /
    // q8_K activation (292/4 GEVM, 1168/16 GEMM) facts are a stage-C materialization the
    // lowering RECONSTRUCTS from the q3_K decode facts, never carried here.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "K-quant q3_K block-quantized contraction request";
    if (getWeightBlockStride() != 110)
      return emitOpError()
             << "requires weight_block_stride == 110 (sizeof block_q3_K: 32 hmask "
                "high-bit + 64 qs low-2-bit + 12 6-bit-packed scales + fp16 d, the "
                "PLAIN K-quant weight layout) for the abstract K-quant q3_K "
                "block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 "
                "d + 256 int8 quants + 16 int16 bsums) for the abstract K-quant "
                "q3_K block-quantized contraction request";
    if (getQuantByteOffset() != 0)
      return emitOpError()
             << "requires quant_byte_offset == 0 (the plain q3_K hmask high-bit plane "
                "leads the block; qs/scales/d trail) for the abstract K-quant q3_K "
                "block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "K-quant q3_K block-quantized contraction request";
  } else if (isCodebookIq4NlFamily) {
    // iq4_nl codebook: QK4_NL == 32, PLAIN block_iq4_nl weight stride 18 (fp16 d + 16
    // nibble bytes), PLAIN block_q8_0 activation stride 34 (fp16 d + 32 int8 quants). The
    // plain nibbles start at +2 (after the inline fp16 d), and the flat 32-block low/high
    // nibble decode into positions i / i+16, so the q8 high half sits at +16 (IDENTICALLY
    // to q4_0). The repacked x16 weight (stride 288, nibbles @32) / block_q8_0{,x4}
    // activation (34/2 GEVM, 136/8 GEMM) facts + the 16-entry non-linear int8 codebook are
    // a stage-C materialization the lowering RECONSTRUCTS (the codebook from kvalues_iq4nl),
    // never carried here.
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK4_NL) for the abstract iq4_nl "
                              "codebook block-quantized contraction request";
    if (getWeightBlockStride() != 18)
      return emitOpError()
             << "requires weight_block_stride == 18 (sizeof block_iq4_nl: fp16 d + "
                "16 nibble bytes, the PLAIN codebook weight layout) for the abstract "
                "iq4_nl codebook block-quantized contraction request";
    if (getActivationBlockStride() != 34)
      return emitOpError()
             << "requires activation_block_stride == 34 (sizeof block_q8_0: fp16 d + "
                "32 int8 quants) for the abstract iq4_nl codebook block-quantized "
                "contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the plain iq4_nl nibbles follow the "
                "inline fp16 d) for the abstract iq4_nl codebook block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (the flat 32-block high "
                "nibble decodes into q8 position i+16) for the abstract iq4_nl "
                "codebook block-quantized contraction request";
  } else if (isCodebookMxfp4Family) {
    // mxfp4 codebook: QK_MXFP4 == 32, PLAIN block_mxfp4 weight stride 17 (uint8 E8M0
    // exponent + 16 nibble bytes), PLAIN block_q8_0 activation stride 34 (fp16 d + 32
    // int8 quants). The plain nibbles start at +1 (after the inline E8M0 exponent byte),
    // and the flat 32-block low/high nibble decode into positions i / i+16, so the q8
    // high half sits at +16 (IDENTICALLY to q4_0 / iq4_nl). The repacked x16 weight
    // (stride 272, E8M0 strip @0, nibbles @16) / block_q8_0{,x4} activation (34/2 GEVM,
    // 136/8 GEMM) facts + the 16-entry doubled-e2m1 int8 codebook are a stage-C
    // materialization the lowering RECONSTRUCTS (the codebook from kvalues_mxfp4), never
    // carried here.
    if (getQk() != 32)
      return emitOpError() << "requires qk == 32 (QK_MXFP4) for the abstract mxfp4 "
                              "codebook block-quantized contraction request";
    if (getWeightBlockStride() != 17)
      return emitOpError()
             << "requires weight_block_stride == 17 (sizeof block_mxfp4: uint8 E8M0 "
                "exponent + 16 nibble bytes, the PLAIN codebook weight layout) for the "
                "abstract mxfp4 codebook block-quantized contraction request";
    if (getActivationBlockStride() != 34)
      return emitOpError()
             << "requires activation_block_stride == 34 (sizeof block_q8_0: fp16 d + "
                "32 int8 quants) for the abstract mxfp4 codebook block-quantized "
                "contraction request";
    if (getQuantByteOffset() != 1)
      return emitOpError()
             << "requires quant_byte_offset == 1 (the plain mxfp4 nibbles follow the "
                "inline E8M0 exponent byte) for the abstract mxfp4 codebook "
                "block-quantized contraction request";
    if (getActivationHighByteOffset() != 16)
      return emitOpError()
             << "requires activation_high_byte_offset == 16 (the flat 32-block high "
                "nibble decodes into q8 position i+16) for the abstract mxfp4 "
                "codebook block-quantized contraction request";
  } else if (isCodebookIq4XsFamily) {
    // iq4_xs codebook: QK_K == 256, PLAIN block_iq4_xs weight stride 136 (fp16 d + uint16
    // scales_h + 4 scales_l bytes + 128 nibble bytes), PLAIN block_q8_K activation stride
    // 292 (fp32 d + 256 int8 quants + 16 int16 bsums). The plain nibbles start at +8
    // (after d(2) + scales_h(2) + scales_l(4)); block_q8_K carries no packed high half
    // (activation_high_byte_offset == 0 sentinel, unused, like the K-quant super-blocks).
    // The repacked x16 weight (stride 2176, nibbles @128, scales_l @64, scales_h @32) /
    // block_q8_K{,x4} activation (292/4 GEVM, 1168/16 GEMM) facts + the 16-entry non-linear
    // int8 codebook + the signed-6 scale facts are a stage-C materialization the lowering
    // RECONSTRUCTS (the codebook from kvalues_iq4nl), never carried here.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract iq4_xs "
                              "codebook block-quantized contraction request";
    if (getWeightBlockStride() != 136)
      return emitOpError()
             << "requires weight_block_stride == 136 (sizeof block_iq4_xs: fp16 d + "
                "uint16 scales_h + 4 scales_l bytes + 128 nibble bytes, the PLAIN "
                "super-block codebook weight layout) for the abstract iq4_xs codebook "
                "block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums) for the abstract iq4_xs codebook "
                "block-quantized contraction request";
    if (getQuantByteOffset() != 8)
      return emitOpError()
             << "requires quant_byte_offset == 8 (the plain iq4_xs nibbles follow the "
                "inline fp16 d + uint16 scales_h + 4 scales_l bytes) for the abstract "
                "iq4_xs codebook block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract iq4_xs "
                "codebook block-quantized contraction request";
  } else if (isGridIq2XxsFamily) {
    // iq2_xxs grid codebook: QK_K == 256, PLAIN block_iq2_xxs weight stride 66 (fp16 d +
    // 32 uint16 qs = 2 + 64), PLAIN block_q8_K activation stride 292 (fp32 d + 256 int8
    // quants + 16 int16 bsums). The plain qs start at +2 (after the inline fp16 d);
    // block_q8_K carries no packed high half (activation_high_byte_offset == 0 sentinel,
    // unused, like the K-quant / iq4_xs super-blocks). The repacked x16 weight (stride
    // 1184, grid-index @160, ls @32, sign @672) / block_q8_K{,x4} activation (292/4 GEVM,
    // 1168/16 GEMM) facts + the FIXED 256-entry grid + the DERIVED signs64 plane are a
    // stage-C materialization the grid lowering RECONSTRUCTS, never carried here.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract iq2_xxs "
                              "grid block-quantized contraction request";
    if (getWeightBlockStride() != 66)
      return emitOpError()
             << "requires weight_block_stride == 66 (sizeof block_iq2_xxs: fp16 d + "
                "32 uint16 qs bytes, the PLAIN super-block grid weight layout) for the "
                "abstract iq2_xxs grid block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums) for the abstract iq2_xxs grid "
                "block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the plain iq2_xxs qs follow the "
                "inline fp16 d) for the abstract iq2_xxs grid block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract iq2_xxs "
                "grid block-quantized contraction request";
  } else if (isGridIq2XsFamily || isGridIq2SFamily) {
    // iq2_xs / iq2_s dual-scale grid codebook: QK_K == 256, PLAIN block_iq2_xs weight
    // stride 74 (fp16 d + 32 uint16 qs + 8 uint8 scales = 2 + 64 + 8) / block_iq2_s stride
    // 82 (fp16 d + 64 uint8 qs + 8 uint8 qh + 8 uint8 scales), PLAIN block_q8_K activation
    // stride 292. The plain qs start at +2 (after the inline fp16 d); block_q8_K carries no
    // packed high half (activation_high_byte_offset == 0 sentinel, unused). The repacked x16
    // weight (stride 1824, grid-index @288, ls @32, sign @1312) / block_q8_K{,x4} activation
    // (292/4 GEVM, 1168/16 GEMM) facts + the FIXED grid + the DERIVED signs plane are a
    // stage-C materialization the grid lowering RECONSTRUCTS, never carried here.
    std::uint64_t plainStride = isGridIq2XsFamily ? 74 : 82;
    llvm::StringRef fmt = isGridIq2XsFamily ? "iq2_xs" : "iq2_s";
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract " << fmt
                           << " grid block-quantized contraction request";
    if (getWeightBlockStride() != plainStride)
      return emitOpError()
             << "requires weight_block_stride == " << plainStride << " (sizeof block_"
             << fmt
             << ", the PLAIN super-block dual-scale grid weight layout) for the "
                "abstract "
             << fmt << " grid block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums) for the abstract "
             << fmt << " grid block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the plain " << fmt
             << " qs follow the inline fp16 d) for the abstract " << fmt
             << " grid block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
             << fmt << " grid block-quantized contraction request";
  } else if (isGridIq1SFamily) {
    // iq1_s (C4a-2) TERNARY-DELTA grid codebook: QK_K == 256, PLAIN block_iq1_s weight
    // stride 50 (fp16 d + 32 uint8 qs + 8 uint16 qh = 2 + 32 + 16), PLAIN block_q8_K
    // activation stride 292. The plain qs start at +2 (after the inline fp16 d);
    // block_q8_K carries no packed high half (activation_high_byte_offset == 0
    // sentinel, unused). The repacked x16 weight (stride 1312, grid-index @288, ls @32,
    // DELTA @160) / block_q8_K{,x4} activation (292/4 + bsums @260 GEVM, 1168/16 +
    // bsums @1040 GEMM) facts + the FIXED 2048-entry ternary grid are a stage-C
    // materialization the grid lowering RECONSTRUCTS, never carried here. NOTE this arm
    // is EXPLICIT rather than falling into the trailing q5_K `else`: without it an
    // iq1_s request is rejected by the q5_K stride pin (176), which is what a
    // fall-through would silently mean.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract iq1_s "
                              "grid block-quantized contraction request";
    if (getWeightBlockStride() != 50)
      return emitOpError()
             << "requires weight_block_stride == 50 (sizeof block_iq1_s: fp16 d + "
                "32 uint8 qs + 8 uint16 qh, the PLAIN super-block ternary-grid "
                "weight layout) for the abstract iq1_s grid block-quantized "
                "contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums -- iq1_s READS the bsums) for the "
                "abstract iq1_s grid block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the plain iq1_s qs follow the "
                "inline fp16 d) for the abstract iq1_s grid block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract iq1_s "
                "grid block-quantized contraction request";
  } else if (isGridIq1MFamily) {
    // iq1_m (C4a-3) TERNARY-DELTA GROUP-SUM grid codebook: QK_K == 256, PLAIN
    // block_iq1_m weight stride 56 (qs[32] + qh[16] + scales[8] = QK_K/8 + QK_K/16 +
    // QK_K/32) -- note there is NO ggml_half member at all, so unlike EVERY other grid
    // sibling the plain quants start at +0, not +2: the fp16 super-block d is ASSEMBLED
    // from four nibbles scattered across the scales words. PLAIN block_q8_K activation
    // stride 292; block_q8_K carries no packed high half (activation_high_byte_offset
    // == 0 sentinel, unused). The repacked x16 weight (stride 1824, grid-index @800,
    // dual ls @32, PER-GROUP DELTA @288) / block_q8_K{,x4} activation (292/4 GEVM,
    // 1168/16 GEMM -- NO bsums either side, since a per-16 bsums entry cannot express
    // iq1_m's per-8 group sum) facts + the FIXED 2048-entry ternary grid are a stage-C
    // materialization the grid lowering RECONSTRUCTS, never carried here. Like the
    // iq1_s arm this one is EXPLICIT rather than falling into the trailing q5_K `else`:
    // without it an iq1_m request is rejected by the q5_K stride pin (176), which is
    // what a fall-through would silently mean.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract iq1_m "
                              "grid block-quantized contraction request";
    if (getWeightBlockStride() != 56)
      return emitOpError()
             << "requires weight_block_stride == 56 (sizeof block_iq1_m: 32 uint8 qs "
                "+ 16 uint8 qh + 8 uint8 scales, the PLAIN super-block ternary-grid "
                "weight layout -- block_iq1_m has NO inline fp16 d) for the abstract "
                "iq1_m grid block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums -- iq1_m does NOT read the bsums, "
                "whose per-16 grouping cannot express its per-8 delta group sum) for "
                "the abstract iq1_m grid block-quantized contraction request";
    if (getQuantByteOffset() != 0)
      return emitOpError()
             << "requires quant_byte_offset == 0 (block_q1_m has NO inline fp16 d: "
                "the plain iq1_m qs start at byte 0 and the fp16 super-block d is "
                "ASSEMBLED from nibbles scattered across the scales words) for the "
                "abstract iq1_m grid block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract iq1_m "
                "grid block-quantized contraction request";
  } else if (isGridIq3XxsFamily) {
    // iq3_xxs (C4a-4) DUAL-ENTRY grid codebook: QK_K == 256, PLAIN block_iq3_xxs weight
    // stride 98 (fp16 d + qs[3*QK_K/8] = 2 + 96; ggml-common.h's static_assert spells it
    // `sizeof(ggml_half) + 3*(QK_K/8)`), PLAIN block_q8_K activation stride 292. The plain
    // qs start at +2 (after the inline fp16 d) and then do DOUBLE DUTY: `gas = x[i].qs +
    // QK_K/4` splits the 96 B into 64 raw grid-index bytes + 8 uint32 aux words carrying
    // the ls and sign selectors. block_q8_K carries no packed high half
    // (activation_high_byte_offset == 0 sentinel, unused). The repacked x16 weight (stride
    // 1696, grid-index @160 -- DOUBLE-width at 1024 B, ls @32, sign-selector @1184) /
    // block_q8_K{,x4} activation (292/4 GEVM, 1168/16 GEMM -- NO bsums either side, since
    // the single-accumulator SignScaleStore fold has no delta term to feed) facts + the
    // FIXED 256-entry uint32 grid + the DERIVED signs64 plane are a stage-C
    // materialization the grid lowering RECONSTRUCTS, never carried here. Like the iq1_s /
    // iq1_m arms this one is EXPLICIT rather than falling into the trailing q5_K `else`:
    // without it an iq3_xxs request is rejected by the q5_K stride pin (176), which is
    // what a fall-through would silently mean.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract iq3_xxs "
                              "grid block-quantized contraction request";
    if (getWeightBlockStride() != 98)
      return emitOpError()
             << "requires weight_block_stride == 98 (sizeof block_iq3_xxs: fp16 d + "
                "3*(QK_K/8) = 96 qs bytes, whose upper 32 are the aux words carrying "
                "the ls + sign selectors, the PLAIN super-block dual-entry-grid weight "
                "layout) for the abstract iq3_xxs grid block-quantized contraction "
                "request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums -- iq3_xxs does NOT read the bsums, "
                "its single-accumulator fold has no delta term) for the abstract "
                "iq3_xxs grid block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the plain iq3_xxs qs follow the "
                "inline fp16 d) for the abstract iq3_xxs grid block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract iq3_xxs "
                "grid block-quantized contraction request";
  } else if (isGridIq3SFamily) {
    // iq3_s (C4a-5) DUAL-ENTRY EXPLICIT-SIGN grid codebook: QK_K == 256, PLAIN block_iq3_s
    // weight stride 110, PLAIN block_q8_K activation stride 292. ggml-common.h's
    // static_assert spells the stride `sizeof(ggml_half) + 13*(QK_K/32) + IQ3S_N_SCALE`
    // = 2 + 104 + 4; laid out, that is d fp16 @0, qs[QK_K/4 = 64] @2, qh[QK_K/32 = 8] @66,
    // signs[QK_K/8 = 32] @74, scales[IQ3S_N_SCALE = QK_K/64 = 4] @106. Unlike iq3_xxs there
    // is NO double-duty region: every plane is its own field, so the plain qs at +2 are
    // purely the low 8 bits of the 64 grid indices and the 9th bit lives in qh. The
    // repacked x16 weight (stride 2720, grid-index @160 -- 2048 B, since the 9-bit index
    // needs a u16 lane where iq3_xxs's byte index needs 1024 B; ls @32, EXPLICIT sign
    // @2208) / block_q8_K{,x4} activation (292/4 GEVM, 1168/16 GEMM -- NO bsums either
    // side, since the single-accumulator SignScaleStore fold has no delta term to feed)
    // facts + the FIXED 512-entry uint32 grid + the DERIVED signs256 plane are a stage-C
    // materialization the grid lowering RECONSTRUCTS, never carried here. EXPLICIT for the
    // same reason every grid arm above is: without it an iq3_s request falls into the
    // trailing q5_K `else` and is rejected by that family's 176 stride pin -- which is
    // exactly what happened when this arm was missing, and is the failure mode the iq3_xxs
    // arm's comment predicted.
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract iq3_s "
                              "grid block-quantized contraction request";
    if (getWeightBlockStride() != 110)
      return emitOpError()
             << "requires weight_block_stride == 110 (sizeof block_iq3_s: fp16 d + "
                "qs[QK_K/4] + qh[QK_K/32] + signs[QK_K/8] + scales[QK_K/64] = "
                "2+64+8+32+4, the PLAIN super-block dual-entry explicit-sign grid "
                "weight layout) for the abstract iq3_s grid block-quantized "
                "contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 d + "
                "256 int8 quants + 16 int16 bsums -- iq3_s does NOT read the bsums, "
                "its single-accumulator fold has no delta term) for the abstract "
                "iq3_s grid block-quantized contraction request";
    if (getQuantByteOffset() != 2)
      return emitOpError()
             << "requires quant_byte_offset == 2 (the plain iq3_s qs follow the "
                "inline fp16 d) for the abstract iq3_s grid block-quantized "
                "contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract iq3_s "
                "grid block-quantized contraction request";
  } else {
    // K-quant q5_K: QK_K == 256, PLAIN block_q5_K weight stride 176 (fp16 d + fp16 dmin
    // + 12 K_SCALE_SIZE 6-bit scales/mins bytes + 32 qh high-bit bytes + 128 nibble
    // bytes, ggml's block_q5_K -- d@0, dmin@2, scales@4, qh@16, qs@48), PLAIN block_q8_K
    // activation stride 292 (fp32 d + 256 int8 quants + 16 int16 bsums). The plain
    // nibbles start at +48 (after d + dmin + 12 scales + 32 qh), and the q8_K activation
    // carries NO packed high half (activation_high_byte_offset == 0 sentinel, unused).
    // The repacked x16 weight (stride 2816, nibbles @768, dmin @32, 6-bit scales @64, qh
    // @256 [the SHARED qh slot, here on a MIN fold]) / q8_K activation (292/4/260 GEVM,
    // 1168/16/1040 GEMM) facts are a stage-C materialization the lowering RECONSTRUCTS
    // from the q5_K decode facts (q5_K == q4_K dual d/dmin + bsums-min fold + qh 5th-bit).
    if (getQk() != 256)
      return emitOpError() << "requires qk == 256 (QK_K) for the abstract "
                              "K-quant q5_K block-quantized contraction request";
    if (getWeightBlockStride() != 176)
      return emitOpError()
             << "requires weight_block_stride == 176 (sizeof block_q5_K: fp16 d + "
                "fp16 dmin + 12 6-bit scales/mins bytes + 32 qh high-bit bytes + 128 "
                "nibble bytes, the PLAIN K-quant weight layout) for the abstract "
                "K-quant q5_K block-quantized contraction request";
    if (getActivationBlockStride() != 292)
      return emitOpError()
             << "requires activation_block_stride == 292 (sizeof block_q8_K: fp32 "
                "d + 256 int8 quants + 16 int16 bsums) for the abstract K-quant "
                "q5_K block-quantized contraction request";
    if (getQuantByteOffset() != 48)
      return emitOpError()
             << "requires quant_byte_offset == 48 (the plain q5_K nibbles follow the "
                "fp16 d + fp16 dmin + 12 scales bytes + 32 qh high-bit bytes) for the "
                "abstract K-quant q5_K block-quantized contraction request";
    if (getActivationHighByteOffset() != 0)
      return emitOpError()
             << "requires activation_high_byte_offset == 0 (block_q8_K carries no "
                "packed high half; the 0 sentinel is unused) for the abstract "
                "K-quant q5_K block-quantized contraction request";
  }

  // Six runtime ABI value operands -- the plain weight base, the plain
  // activation base, the fp32 output, the runtime element count n, the runtime
  // column count nc (carried ALWAYS so the repack branch can reach it; the
  // block-dot identity lowering DROPS it), and the !weft_rvv.vl token.
  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one plain weight base pointer, one plain activation "
              "base pointer, one output pointer, one runtime element-count, one "
              "runtime column-count (nc), one !weft_rvv.vl operand, and one i32 "
              "LMUL m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS PLAIN block_q4_0 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 byte "
              "array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of weight columns; carried always so a later "
              "repack branch can reach it, dropped by the block-dot identity "
              "lowering)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the abstract block-quantized contraction request";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the abstract block-quantized contraction request";

  return mlir::success();
}

mlir::LogicalResult GgmlGemmTileQ40Q80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16 scale model, the block-format structural facts, and the bounded
  // activation-column count M. Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected
  // fail-closed (I7).
  auto isAllowedGemmTileAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" || name == "quant_byte_offset" ||
           name == "activation_high_byte_offset" || name == "activation_cols";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_0_q8_0_gemm_tile keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedGemmTileAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q4_0 x Q8_0 GEMM tile attributes "
                "'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'quant_byte_offset', "
                "'activation_high_byte_offset', and 'activation_cols'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q4_0_q8_0_gemm_tile")
    return emitOpError()
           << "currently supports only kind \"ggml_q4_0_q8_0_gemm_tile\" for "
              "the bounded ggml Q4_0 x Q8_0 GEMM tile typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y\" for the "
              "ggml Q4_0 x Q8_0 GEMM tile route";
  // ggml's externally-defined block format (ggml-common.h), identical to the
  // per-row block dot: QK8_0 == 32, block_q4_0 stride 18, block_q8_0 stride 34,
  // quants at byte offset +2, the q8 high half at +16. Pin them so a malformed
  // typed body cannot lower under the GEMM tile emission.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_0) for the ggml Q4_0 x "
                            "Q8_0 GEMM tile route";
  if (getWeightBlockStride() != 18)
    return emitOpError()
           << "requires weight_block_stride == 18 (sizeof block_q4_0) for the "
              "ggml Q4_0 x Q8_0 GEMM tile route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
              "the ggml Q4_0 x Q8_0 GEMM tile route";
  if (getQuantByteOffset() != 2)
    return emitOpError()
           << "requires quant_byte_offset == 2 (quants follow the inline fp16 "
              "scale) for the ggml Q4_0 x Q8_0 GEMM tile route";
  if (getActivationHighByteOffset() != 16)
    return emitOpError()
           << "requires activation_high_byte_offset == 16 (q8 high half) for "
              "the ggml Q4_0 x Q8_0 GEMM tile route";

  // The bounded activation-column count M: G1 fixes a small tile so the inner
  // M-column loop and the M-wide fp32 accumulator array stay register-bounded.
  // Reject M outside the bounded [1, 16] band fail-closed (I7); the autotuner's
  // measurement-tuned M-block is G3.
  int64_t activationCols = getActivationCols();
  if (activationCols < 1 || activationCols > 16)
    return emitOpError()
           << "requires activation_cols in [1, 16] (the bounded G1 GEMM tile "
              "column count; the measurement-tuned M-block is G3); got "
           << activationCols;

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one activation column-stride, one output pointer, one runtime "
              "element-count runtime ABI operand, one !weft_rvv.vl operand, and "
              "one i32 LMUL m1 result";

  // The buffer operands and the element count are runtime ABI values; the
  // weight/activation bases address the AoS byte arrays as const uint8_t *, the
  // output is a float *, and the element count carries n. The column stride is
  // the runtime byte distance between two adjacent activation columns.
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_0 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 columns "
              "byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, M outputs)";
  if (!llvm::isa<mlir::IndexType>(getActivationColumnStride().getType()))
    return emitOpError()
           << "requires the activation column-stride operand to be a runtime "
              "index value (the per-column activation byte stride)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q4_0 x Q8_0 GEMM tile route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q4_0 x Q8_0 GEMM tile";

  return mlir::success();
}

mlir::LogicalResult GgmlGemmQ40Q80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16 scale model, the block-format structural facts, the bounded inner
  // activation-column block count M. Formula candidates, costs and selection
  // provenance remain transient and are not accepted as IR attributes. Anything else
  // -- a forbidden local element_count/SEW/LMUL/policy attr, or an unexpected
  // name -- is rejected fail-closed (I7). The runtime row/column counts and the
  // row strides are RUNTIME ABI value operands (the full ggml-gemm-like ABI).
  auto isAllowedGemmAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" || name == "quant_byte_offset" ||
           name == "activation_high_byte_offset" || name == "activation_cols";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_0_q8_0_gemm keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL/nr/nc/bx/bs in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedGemmAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q4_0 x Q8_0 full GEMM attributes "
                "'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'quant_byte_offset', "
                "'activation_high_byte_offset', and 'activation_cols'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q4_0_q8_0_gemm")
    return emitOpError()
           << "currently supports only kind \"ggml_q4_0_q8_0_gemm\" for "
              "the bounded ggml Q4_0 x Q8_0 full GEMM typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y\" for the "
              "ggml Q4_0 x Q8_0 full GEMM route";
  // ggml's externally-defined block format (ggml-common.h), identical to the
  // per-row block dot / GEMM tile: QK8_0 == 32, block_q4_0 stride 18,
  // block_q8_0 stride 34, quants at byte offset +2, the q8 high half at +16.
  // Pin them so a malformed typed body cannot lower under the GEMM emission.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_0) for the ggml Q4_0 x "
                            "Q8_0 full GEMM route";
  if (getWeightBlockStride() != 18)
    return emitOpError()
           << "requires weight_block_stride == 18 (sizeof block_q4_0) for the "
              "ggml Q4_0 x Q8_0 full GEMM route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
              "the ggml Q4_0 x Q8_0 full GEMM route";
  if (getQuantByteOffset() != 2)
    return emitOpError()
           << "requires quant_byte_offset == 2 (quants follow the inline fp16 "
              "scale) for the ggml Q4_0 x Q8_0 full GEMM route";
  if (getActivationHighByteOffset() != 16)
    return emitOpError()
           << "requires activation_high_byte_offset == 16 (q8 high half) for "
              "the ggml Q4_0 x Q8_0 full GEMM route";

  // The bounded inner activation-column block count M: G2 fixed a small tile so
  // the inner M-column loop and the M-wide fp32 accumulator array stay
  // register-bounded. G3 makes M a measurement-tuned cache-blocking knob, so the
  // attribute is OPTIONAL and the materialize pass STAMPS the measured-best M
  // (absent => the emitter falls back to its default tile). When PRESENT, reject
  // M outside the bounded [1, 16] band fail-closed (I7).
  if (std::optional<int64_t> activationCols = getActivationCols()) {
    if (*activationCols < 1 || *activationCols > 16)
      return emitOpError()
             << "requires activation_cols in [1, 16] (the bounded inner GEMM "
                "column block; the measurement-tuned M-block is G3); got "
             << *activationCols;
  }

  if (op->getNumOperands() != 10 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one activation column-stride, one output pointer, one runtime "
              "element-count, one runtime row-count, one runtime column-count, "
              "one weight-row byte-stride, one output-row float-stride runtime "
              "ABI operand, one !weft_rvv.vl operand, and one i32 LMUL m1 result";

  // The buffer operands and the counts/strides are runtime ABI values; the
  // weight/activation bases address the AoS byte arrays as const uint8_t *, the
  // output is a float *, the element count carries n, the row/column counts
  // carry nr/nc, and the strides carry the per-row byte stride (bx) and the
  // per-output-row float stride (bs).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_0 weight-rows byte "
              "array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 columns "
              "byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, NR x nc outputs)";
  if (!llvm::isa<mlir::IndexType>(getActivationColumnStride().getType()))
    return emitOpError()
           << "requires the activation column-stride operand to be a runtime "
              "index value (the per-column activation byte stride)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getRowCount().getType()))
    return emitOpError()
           << "requires the row-count operand to be a runtime index value (nr, "
              "the number of weight rows)";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of activation columns)";
  if (!llvm::isa<mlir::IndexType>(getWeightRowStride().getType()))
    return emitOpError()
           << "requires the weight-row-stride operand to be a runtime index "
              "value (bx, the per-weight-row byte stride)";
  if (!llvm::isa<mlir::IndexType>(getOutputRowStride().getType()))
    return emitOpError()
           << "requires the output-row-stride operand to be a runtime index "
              "value (bs, the per-output-row float stride)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q4_0 x Q8_0 full GEMM route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q4_0 x Q8_0 full GEMM";

  return mlir::success();
}

mlir::LogicalResult GgmlRepackGemvQ50Q80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16 scale model, and the 16x1 REPACKED q5_0 block-format structural
  // facts (qs nibble offset AND the transposed bit-packed qh offset). Anything
  // else is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "weight_qh_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "weight_interleave" || name == "half_lanes" ||
           name == "integer_core_lmul" ||
           name == "weft_rvv.weight_layout_contract";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemv_q5_0_q8_0 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/nc in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q5_0 x Q8_0 16x1-repacked GEMV "
                "attributes 'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'weight_quant_byte_offset', "
                "'weight_qh_byte_offset', 'activation_quant_byte_offset', "
                "'weight_interleave', 'half_lanes', and 'integer_core_lmul'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_repack_gemv_q5_0_q8_0")
    return emitOpError()
           << "currently supports only kind \"ggml_repack_gemv_q5_0_q8_0\" for "
              "the bounded ggml Q5_0 x Q8_0 16x1-repacked GEMV typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y\" for the "
              "ggml Q5_0 x Q8_0 16x1-repacked GEMV route";

  // The 16x1 repacked q5_0 decode ABI (pinned fail-closed I7): QK == 32,
  // block_q5_0x16 weight stride 352 (16 inline fp16 scales + 256 interleaved
  // nibble bytes + 64 transposed bit-packed qh mask bytes = 16*22), block_q8_0
  // activation stride 34, weight nibbles at byte +32, the transposed qh masks at
  // byte +288 (after the 256 nibble bytes), activation quants at byte +2, 16
  // weight rows per group, the VLEN-derived half-lane split width.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK5_0) for the ggml Q5_0 x Q8_0 "
                            "16x1-repacked GEMV route";
  if (getWeightBlockStride() != 352)
    return emitOpError()
           << "requires weight_block_stride == 352 (sizeof block_q5_0x16: 32 B "
              "scales + 256 B nibbles + 64 B transposed qh = 16*22) for the "
              "ggml Q5_0 x Q8_0 16x1-repacked GEMV route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0, the "
              "plain single-column q8_0 activation stream) for the ggml Q5_0 x "
              "Q8_0 16x1-repacked GEMV route";
  if (getWeightQuantByteOffset() != 32)
    return emitOpError()
           << "requires weight_quant_byte_offset == 32 (the 16 inline fp16 "
              "scales precede the interleaved nibble bytes) for the ggml Q5_0 x "
              "Q8_0 16x1-repacked GEMV route";
  if (getWeightQhByteOffset() != 288)
    return emitOpError()
           << "requires weight_qh_byte_offset == 288 (the 256 interleaved nibble "
              "bytes precede the 64 transposed bit-packed qh mask bytes) for the "
              "ggml Q5_0 x Q8_0 16x1-repacked GEMV route";
  if (getActivationQuantByteOffset() != 2)
    return emitOpError()
           << "requires activation_quant_byte_offset == 2 (the single inline "
              "fp16 scale precedes the int8 quants) for the ggml Q5_0 x Q8_0 "
              "16x1-repacked GEMV route";
  if (getWeightInterleave() != 16)
    return emitOpError() << "requires weight_interleave == 16 (the 16x1 "
                            "block-as-lane repack width) for the ggml Q5_0 x "
                            "Q8_0 16x1-repacked GEMV route";
  if (getHalfLanes() != 8 && getHalfLanes() != 16)
    return emitOpError()
           << "requires half_lanes in {8, 16} (the resource-aware e16m1 strip "
              "width: 8 at VLEN=128 -> two 8-lane halves, 16 at VLEN=256 -> one "
              "16-lane strip) for the ggml Q5_0 x Q8_0 16x1-repacked GEMV route";
  if (getWeightInterleave() % getHalfLanes() != 0)
    return emitOpError()
           << "requires half_lanes to divide weight_interleave (16) so the "
              "16-block-as-lane group tiles into whole strips for the ggml Q5_0 "
              "x Q8_0 16x1-repacked GEMV route";

  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "requires integer_core_lmul in {\"mf2\", \"m1\"} for the ggml "
                "Q5_0 x Q8_0 16x1-repacked GEMV route; got \""
             << coreLmul << "\"";
    if (coreLmul == "m1" && getHalfLanes() != 16)
      return emitOpError()
             << "requires half_lanes == 16 when integer_core_lmul is \"m1\" "
                "(the whole-LMUL i8m1 strip is 16 i8 lanes, ONE 16-lane strip) "
                "for the ggml Q5_0 x Q8_0 16x1-repacked GEMV route";
  }

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one repacked weight base pointer, one plain activation "
              "base pointer, one output pointer, one runtime element-count, one "
              "runtime column-count, one !weft_rvv.vl operand, and one i32 LMUL "
              "m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q5_0x16 repacked weight "
              "byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 plain "
              "activation byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, nc outputs)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of weight columns)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q5_0 x Q8_0 16x1-repacked GEMV route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q5_0 x Q8_0 16x1-repacked GEMV";

  return mlir::success();
}

mlir::LogicalResult GgmlRepackGemvQ51Q81Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16-plus-min scale model, and the 16x1 REPACKED q5_1 block-format
  // structural facts -- the UNION of the q4_1 GEVM's SECOND-scale byte offsets
  // (min/sum) and the q5_0 GEVM's transposed bit-packed qh offset. Anything else
  // is rejected fail-closed (I7). The runtime nc count is a RUNTIME ABI value
  // operand; there is NO nr/bs (GEVM is single-column).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "weight_qh_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "weight_min_byte_offset" ||
           name == "activation_sum_byte_offset" ||
           name == "weight_interleave" || name == "half_lanes" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemv_q5_1_q8_1 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/nc in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q5_1 x Q8_1 16x1-repacked GEMV "
                "attributes 'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'weight_quant_byte_offset', "
                "'weight_qh_byte_offset', 'activation_quant_byte_offset', "
                "'weight_min_byte_offset', 'activation_sum_byte_offset', "
                "'weight_interleave', 'half_lanes', and 'integer_core_lmul'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_repack_gemv_q5_1_q8_1")
    return emitOpError()
           << "currently supports only kind \"ggml_repack_gemv_q5_1_q8_1\" for "
              "the bounded ggml Q5_1 x Q8_1 16x1-repacked GEMV typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y-plus-min")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y-plus-min\" "
              "for the ggml Q5_1 x Q8_1 16x1-repacked GEMV route";

  // The 16x1 repacked q5_1 decode ABI (pinned fail-closed I7): QK == 32,
  // block_q5_1x16 weight stride 384 (16 inline fp16 d + 16 inline fp16 m + 256
  // interleaved nibble bytes + 64 transposed bit-packed qh mask bytes),
  // block_q8_1 activation stride 36 (fp16 d + fp16 s + 32 int8 quants -- the
  // PLAIN q8_1 stream, NOT an interleaved x4), weight nibbles at byte +64 (after
  // the 16 d + 16 m fp16 scales), the per-row MIN strip at byte +32 (after the 16
  // d scales), the transposed qh masks at byte +320 (after the 256 nibble bytes),
  // activation quants at byte +4 (after the d + s fp16 scales), the activation
  // scaled-sum at byte +2 (after d), 16 weight rows per group, the VLEN-derived
  // half-lane split width.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_1) for the ggml Q5_1 x Q8_1 "
                            "16x1-repacked GEMV route";
  if (getWeightBlockStride() != 384)
    return emitOpError()
           << "requires weight_block_stride == 384 (sizeof block_q5_1x16: 16 "
              "fp16 d + 16 fp16 m + 256 nibble bytes + 64 transposed qh bytes) "
              "for the ggml Q5_1 x Q8_1 16x1-repacked GEMV route";
  if (getActivationBlockStride() != 36)
    return emitOpError()
           << "requires activation_block_stride == 36 (sizeof block_q8_1, the "
              "plain single-column q8_1 activation stream) for the ggml Q5_1 x "
              "Q8_1 16x1-repacked GEMV route";
  if (getWeightQuantByteOffset() != 64)
    return emitOpError()
           << "requires weight_quant_byte_offset == 64 (the 16 inline fp16 d + "
              "16 inline fp16 m scales precede the interleaved nibble bytes) for "
              "the ggml Q5_1 x Q8_1 16x1-repacked GEMV route";
  if (getWeightMinByteOffset() != 32)
    return emitOpError()
           << "requires weight_min_byte_offset == 32 (the 16 per-row fp16 MIN m "
              "strip follows the 16 inline fp16 delta d scales) for the ggml "
              "Q5_1 x Q8_1 16x1-repacked GEMV route";
  if (getWeightQhByteOffset() != 320)
    return emitOpError()
           << "requires weight_qh_byte_offset == 320 (the 16 d + 16 m scales and "
              "256 interleaved nibble bytes precede the 64 transposed bit-packed "
              "qh mask bytes) for the ggml Q5_1 x Q8_1 16x1-repacked GEMV route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (the d + s inline fp16 "
              "scales precede the int8 quants) for the ggml Q5_1 x Q8_1 "
              "16x1-repacked GEMV route";
  if (getActivationSumByteOffset() != 2)
    return emitOpError()
           << "requires activation_sum_byte_offset == 2 (the block_q8_1 scaled "
              "sum s follows the inline fp16 delta d) for the ggml Q5_1 x Q8_1 "
              "16x1-repacked GEMV route";
  if (getWeightInterleave() != 16)
    return emitOpError() << "requires weight_interleave == 16 (the 16x1 "
                            "block-as-lane repack width) for the ggml Q5_1 x "
                            "Q8_1 16x1-repacked GEMV route";
  if (getHalfLanes() != 8 && getHalfLanes() != 16)
    return emitOpError()
           << "requires half_lanes in {8, 16} (the resource-aware e16m1 strip "
              "width: 8 at VLEN=128 -> two 8-lane halves, 16 at VLEN=256 -> one "
              "16-lane strip) for the ggml Q5_1 x Q8_1 16x1-repacked GEMV route";
  if (getWeightInterleave() % getHalfLanes() != 0)
    return emitOpError()
           << "requires half_lanes to divide weight_interleave (16) so the "
              "16-block-as-lane group tiles into whole strips for the ggml Q5_1 "
              "x Q8_1 16x1-repacked GEMV route";

  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "requires integer_core_lmul in {\"mf2\", \"m1\"} (the RVV1.0 "
                "fractional core anchor or the RVV0.7.1 whole-LMUL core anchor) "
                "for the ggml Q5_1 x Q8_1 16x1-repacked GEMV route; got \""
             << coreLmul << "\"";
    if (coreLmul == "m1" && getHalfLanes() != 16)
      return emitOpError()
             << "requires half_lanes == 16 when integer_core_lmul is \"m1\" "
                "(the whole-LMUL i8m1 strip is 16 i8 lanes, tiling the "
                "16-block-as-lane group into exactly ONE 16-lane strip) for the "
                "ggml Q5_1 x Q8_1 16x1-repacked GEMV route";
  }

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one repacked weight base pointer, one plain activation "
              "base pointer, one output pointer, one runtime element-count, one "
              "runtime column-count, one !weft_rvv.vl operand, and one i32 LMUL "
              "m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q5_1x16 repacked weight "
              "byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_1 plain "
              "activation byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, nc outputs)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of weight columns)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q5_1 x Q8_1 16x1-repacked GEMV route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q5_1 x Q8_1 16x1-repacked GEMV";

  return mlir::success();
}

mlir::LogicalResult GgmlPackQ40ToX16Op::verify() {
  mlir::Operation *op = getOperation();

  // The option-2 stage-C1b PACK op carries ONLY its bounded mirror attrs (I4):
  // the operation kind and the plain block_q4_0 -> block_q4_0x16 pack structural
  // facts. Anything else -- a forbidden local element_count/SEW/LMUL/policy
  // attr, or an unexpected name -- is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "src_block_stride" ||
           name == "dst_block_stride" || name == "src_quant_byte_offset" ||
           name == "dst_quant_byte_offset" || name == "weight_interleave" ||
           name == "xor_mask";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.pack_q4_0_to_q4_0x16 is a pure scalar byte "
                "transform and keeps SEW/LMUL/policy on setvl/with_vl, runtime "
                "nblocks in the surrounding control-plane IR";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml plain q4_0 -> q4_0x16 pack "
                "attributes 'kind', 'qk', 'src_block_stride', "
                "'dst_block_stride', 'src_quant_byte_offset', "
                "'dst_quant_byte_offset', 'weight_interleave', and 'xor_mask'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_pack_q4_0_to_q4_0x16")
    return emitOpError()
           << "currently supports only kind \"ggml_pack_q4_0_to_q4_0x16\" for "
              "the bounded ggml plain q4_0 -> q4_0x16 pack typed surface";

  // The pack ABI (the byte layout make_block_q4_0x16 depends on, pinned
  // fail-closed I7): QK == 32, block_q4_0 source stride 18 (1 inline fp16 scale
  // + 16 nibble bytes), block_q4_0x16 destination stride 288 (16 inline fp16
  // scales + 256 interleaved nibble bytes), source quants at byte offset +2
  // (after the 1 fp16 scale), destination quants at byte offset +32 (after the
  // 16 fp16 scales), 16 source blocks interleaved per output block, and the
  // offset-binary XOR mask 0x88.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK4_0) for the ggml plain q4_0 "
                            "-> q4_0x16 pack route";
  if (getSrcBlockStride() != 18)
    return emitOpError()
           << "requires src_block_stride == 18 (sizeof block_q4_0) for the ggml "
              "plain q4_0 -> q4_0x16 pack route";
  if (getDstBlockStride() != 288)
    return emitOpError()
           << "requires dst_block_stride == 288 (sizeof block_q4_0x16) for the "
              "ggml plain q4_0 -> q4_0x16 pack route";
  if (getSrcQuantByteOffset() != 2)
    return emitOpError()
           << "requires src_quant_byte_offset == 2 (the single inline fp16 "
              "scale precedes the 16 nibble bytes) for the ggml plain q4_0 -> "
              "q4_0x16 pack route";
  if (getDstQuantByteOffset() != 32)
    return emitOpError()
           << "requires dst_quant_byte_offset == 32 (the 16 inline fp16 scales "
              "precede the 256 interleaved nibble bytes) for the ggml plain q4_0 "
              "-> q4_0x16 pack route";
  if (getWeightInterleave() != 16)
    return emitOpError() << "requires weight_interleave == 16 (the 16-way "
                            "block-as-lane interleave width) for the ggml plain "
                            "q4_0 -> q4_0x16 pack route";
  if (getXorMask() != 0x88)
    return emitOpError()
           << "requires xor_mask == 0x88 (the offset-binary bias the consumer "
              "GEMV expects) for the ggml plain q4_0 -> q4_0x16 pack route";

  return mlir::success();
}

mlir::LogicalResult GgmlRepackGemvQ80Q80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16 scale model, and the 16x1 REPACKED block-format structural facts.
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7). The runtime nc count is a
  // RUNTIME ABI value operand. There is NO nr/bs (the GEMV is single-column).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "weight_interleave" || name == "half_lanes" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemv_q8_0_q8_0 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/nc in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q8_0 x Q8_0 16x1-repacked GEMV "
                "attributes 'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'weight_interleave', "
                "'half_lanes', and 'integer_core_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_repack_gemv_q8_0_q8_0")
    return emitOpError()
           << "currently supports only kind \"ggml_repack_gemv_q8_0_q8_0\" for "
              "the bounded ggml Q8_0 x Q8_0 16x1-repacked GEMV typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y\" for the "
              "ggml Q8_0 x Q8_0 16x1-repacked GEMV route";

  // The 16x1 repacked decode ABI (the byte layout the q8_0-16x1 GEVM kernel
  // depends on, pinned fail-closed I7): QK == 32, block_q8_0x16 weight stride
  // 544 (16 inline fp16 scales = 32 bytes + 16*32 = 512 interleaved int8 quant
  // bytes), block_q8_0 activation stride 34 (1 inline fp16 scale + 32 int8
  // quants -- the PLAIN q8_0 stream, NOT the GEMM's interleaved q8_0x4), weight
  // quants at byte offset +32 (after the 16 fp16 scales), activation quants at
  // byte offset +2 (after the 1 fp16 scale), 16 weight rows per group, and the
  // VLEN=128 half-lane split width 8.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_0) for the ggml Q8_0 x Q8_0 "
                            "16x1-repacked GEMV route";
  if (getWeightBlockStride() != 544)
    return emitOpError()
           << "requires weight_block_stride == 544 (sizeof block_q8_0x16: 16 "
              "fp16 scales = 32 bytes + 16*32 = 512 int8 quant bytes) for the "
              "ggml Q8_0 x Q8_0 16x1-repacked GEMV route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0, the "
              "plain single-column q8_0 activation stream) for the ggml Q8_0 x "
              "Q8_0 16x1-repacked GEMV route";
  if (getWeightQuantByteOffset() != 32)
    return emitOpError()
           << "requires weight_quant_byte_offset == 32 (the 16 inline fp16 "
              "scales precede the interleaved int8 quant bytes) for the ggml "
              "Q8_0 x Q8_0 16x1-repacked GEMV route";
  if (getActivationQuantByteOffset() != 2)
    return emitOpError()
           << "requires activation_quant_byte_offset == 2 (the single inline "
              "fp16 scale precedes the int8 quants) for the ggml Q8_0 x Q8_0 "
              "16x1-repacked GEMV route";
  if (getWeightInterleave() != 16)
    return emitOpError() << "requires weight_interleave == 16 (the 16x1 "
                            "block-as-lane repack width) for the ggml Q8_0 x "
                            "Q8_0 16x1-repacked GEMV route";
  // half_lanes is the resource-aware strip width: the e16m1 lane count the
  // 16-block-as-lane group is tiled into. It MUST divide the weight interleave
  // (16) so the group splits into whole strips, and is bounded to the VLEN-derived
  // set {8, 16}: 8 at VLEN=128 (two disjoint 8-lane halves), 16 at VLEN=256 (one
  // 16-lane strip). This safety invariant holds ONLY because the repack is 16-way
  // interleaved (block_q8_0x16: 512 qs[] bytes = 16 blocks-as-lanes, byte i =
  // block(i%16) offset(i/16)); a 16-lane strip at VLEN=256 therefore reads
  // BYTE-IDENTICAL repacked data to the two 8-lane halves at VLEN=128. Any other
  // width (e.g. 12) is rejected fail-closed (I7).
  if (getHalfLanes() != 8 && getHalfLanes() != 16)
    return emitOpError()
           << "requires half_lanes in {8, 16} (the resource-aware e16m1 strip "
              "width: 8 at VLEN=128 -> two 8-lane halves, 16 at VLEN=256 -> one "
              "16-lane strip; the strip is valid only because the 16-way "
              "interleaved repack makes a 16-lane strip read byte-identical data "
              "to two 8-lane halves) for the ggml Q8_0 x Q8_0 16x1-repacked GEMV "
              "route";
  if (getWeightInterleave() % getHalfLanes() != 0)
    return emitOpError()
           << "requires half_lanes to divide weight_interleave (16) so the "
              "16-block-as-lane group tiles into whole strips for the ggml Q8_0 "
              "x Q8_0 16x1-repacked GEMV route";

  // The optional integer_core_lmul anchors the per-strip integer-product chain
  // (the *how*, never the *what*; the 16-way interleaved repack reads the SAME
  // bytes either way). Only two anchors are legal, each pinned to its strip
  // width fail-closed (I7):
  //   * absent / "mf2" -- the RVV1.0 fractional chain (i8mf2 -> i16m1 -> i32m2
  //     -> f32m2), legal at half_lanes in {8, 16} (the strip width above).
  //   * "m1" -- the WHOLE-LMUL chain RVV0.7.1 requires (i8m1 -> i16m2 -> i32m4
  //     -> f32m4); the i8m1 strip is 16 i8 lanes at VLEN=128, so it tiles the
  //     16-block-as-lane group into exactly ONE 16-lane strip -- half_lanes MUST
  //     be 16. An "m1" anchor with half_lanes 8 (a two-strip whole-LMUL form)
  //     is rejected: it would re-introduce a fractional read.
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "requires integer_core_lmul in {\"mf2\", \"m1\"} (the RVV1.0 "
                "fractional core anchor or the RVV0.7.1 whole-LMUL core anchor) "
                "for the ggml Q8_0 x Q8_0 16x1-repacked GEMV route; got \""
             << coreLmul << "\"";
    if (coreLmul == "m1" && getHalfLanes() != 16)
      return emitOpError()
             << "requires half_lanes == 16 when integer_core_lmul is \"m1\" "
                "(the whole-LMUL i8m1 strip is 16 i8 lanes, tiling the "
                "16-block-as-lane group into exactly ONE 16-lane strip) for the "
                "ggml Q8_0 x Q8_0 16x1-repacked GEMV route";
  }

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one repacked weight base pointer, one plain activation "
              "base pointer, one output pointer, one runtime element-count, one "
              "runtime column-count, one !weft_rvv.vl operand, and one i32 LMUL "
              "m1 result";

  // The buffer operands are runtime ABI values: the repacked weight/plain
  // activation bases address the AoS byte arrays as const uint8_t *, the output
  // is float *.
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q8_0x16 repacked weight "
              "byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 plain "
              "activation byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, nc outputs)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of weight columns)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q8_0 x Q8_0 16x1-repacked GEMV route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q8_0 x Q8_0 16x1-repacked GEMV";

  return mlir::success();
}

// NOTE (G3 主线A T2-construct): the q4_K 16x1-REPACKED GEVM + GEMM monolith op
// verifiers (GgmlRepackGem{v,m}Q4KQ8KOp::verify) are RETIRED to the front door with
// their ops. The K-quant repack is now CONSTRUCTED as the typed
// weft_rvv.typed_repack_gem{v,m}_loop_body region carrying the
// weft_rvv.repack_gem{v,m}_kquant_core brick (verified below), the SAME retirement the
// ternary batch (tq2_0/tq1_0) took.

// Shared allow-list + decode/lmul checks for the two K-quant repack core bricks
// (GEVM/GEMM). The bounded local attrs are 'kind', 'decode_model', the two
// within-block byte offsets, and the OPTIONAL integer_core_lmul resource anchor. The
// K-quant dmin/scales/bsums byte offsets + n_subblocks are the enclosing loop op's
// block-format facts, NOT the core brick's (the brick mirrors the ternary core's
// bounded surface exactly; the extra super-block facts ride on the loop body op).
static mlir::LogicalResult
verifyRepackKQuantCoreCommon(mlir::Operation *op,
                             const std::function<mlir::InFlightDiagnostic()> &err,
                             llvm::StringRef expectedKind,
                             llvm::StringRef kindGot,
                             llvm::StringRef decodeModel,
                             std::optional<llvm::StringRef> coreLmul) {
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "decode_model" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return err()
             << "does not accept attribute '" << attr.getName()
             << "'; the K-quant repack core keeps SEW/LMUL/policy on "
                "setvl/with_vl and runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return err() << "only accepts the bounded K-quant repack core attributes "
                      "'kind', 'decode_model', 'weight_quant_byte_offset', "
                      "'activation_quant_byte_offset', and 'integer_core_lmul'; "
                      "unexpected attribute '"
                   << attr.getName() << "'";
  }
  if (kindGot != expectedKind)
    return err() << "currently supports only kind \"" << expectedKind
                 << "\" for the bounded K-quant 16x1-repacked per-block "
                    "lane-wise dual-scale+min dot integer-core typed surface";
  // The bounded K-quant decode family: q4_K (dual d/dmin + bsums-min), q6_K (6-bit
  // two-plane single-accumulator no-min), OR q2_K (2-bit dual d/dmin + bsums-min)
  // super-block repack, all retired to the front door. The fold arity (min vs no-min)
  // is discriminated by the enclosing loop op's fold_model; the core brick carries the
  // decode_model WHAT (q2_K and q4_K share the min fold, differing only in the decode
  // leaf).
  if (decodeModel != "q4_K" && decodeModel != "q6_K" && decodeModel != "q2_K" &&
      decodeModel != "q3_K" && decodeModel != "q5_K")
    return err() << "only accepts decode_model \"q4_K\" (the K-quant super-block "
                    "dual-scale + bsums-min repack), \"q6_K\" (the 6-bit two-plane "
                    "single-accumulator no-min repack), \"q2_K\" (the 2-bit "
                    "dual-scale + bsums-min repack), \"q3_K\" (the 3-bit "
                    "subtractive-hmask single-accumulator no-min repack), or "
                    "\"q5_K\" (the 5-bit nibble + qh-5th-bit dual-scale + bsums-min "
                    "repack); got \""
                 << decodeModel << "\"";
  if (coreLmul.has_value() && *coreLmul != "mf2" && *coreLmul != "m1")
    return err() << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 "
                    "fractional chain) or \"m1\" (the RVV0.7 whole-LMUL chain); "
                    "got \""
                 << *coreLmul << "\"";
  return mlir::success();
}

mlir::LogicalResult RepackGemvKQuantCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackKQuantCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemv_kquant_core",
          getKind(), getDecodeModel(), getIntegerCoreLmul())))
    return mlir::failure();

  if (op->getNumOperands() != 4 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked block_q4_Kx16 weight base, the plain "
              "block_q8_K activation base, one !weft_rvv.vl operand, one "
              "block_index induction operand, and one or more per-strip i32 vector "
              "results (one per disjoint strip -- numHalves total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-strip result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-strip combined K-quant sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-strip results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise K-quant dual-scale+min core";
  return mlir::success();
}

mlir::LogicalResult RepackGemmKQuantCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackKQuantCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemm_kquant_core",
          getKind(), getDecodeModel(), getIntegerCoreLmul())))
    return mlir::failure();

  if (op->getNumOperands() != 5 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked block_q4_Kx16 weight base, the interleaved "
              "block_q8_Kx4 activation base, one !weft_rvv.vl operand, one "
              "block_index induction operand, one strip_row_offset operand, and "
              "one or more per-column i32 vector results (columnsPerPass total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  if (!llvm::isa<mlir::IndexType>(getStripRowOffset().getType()))
    return emitOpError()
           << "requires the strip_row_offset operand to be index-typed (the "
              "runtime strip row offset, region argument 1)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-column result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-column combined K-quant sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-column results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise K-quant dual-scale+min core";
  return mlir::success();
}

// Shared allow-list + decode/lmul checks for the two CODEBOOK repack core bricks
// (GEVM/GEMM). The bounded local attrs are 'kind', 'decode_model', the two within-block
// byte offsets, the 16-entry non-linear int8 'codebook' DenseI8ArrayAttr, and the
// OPTIONAL integer_core_lmul resource anchor. The per-block strides, qk, the interleaves,
// and the resource-aware strip width are the enclosing loop op's block-format facts (the
// codebook core mirrors the K-quant core's bounded surface, PLUS the load-bearing
// codebook table the MEMORY gather indexes).
static mlir::LogicalResult
verifyRepackCodebookCoreCommon(mlir::Operation *op,
                               const std::function<mlir::InFlightDiagnostic()> &err,
                               llvm::StringRef expectedKind,
                               llvm::StringRef kindGot,
                               llvm::StringRef decodeModel,
                               llvm::ArrayRef<int8_t> codebook,
                               std::optional<llvm::StringRef> coreLmul) {
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "decode_model" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" || name == "codebook" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return err()
             << "does not accept attribute '" << attr.getName()
             << "'; the codebook repack core keeps SEW/LMUL/policy on "
                "setvl/with_vl and runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return err() << "only accepts the bounded codebook repack core attributes "
                      "'kind', 'decode_model', 'weight_quant_byte_offset', "
                      "'activation_quant_byte_offset', 'codebook', and "
                      "'integer_core_lmul'; unexpected attribute '"
                   << attr.getName() << "'";
  }
  if (kindGot != expectedKind)
    return err() << "currently supports only kind \"" << expectedKind
                 << "\" for the bounded codebook 16x1-repacked per-block "
                    "lane-wise memory-gather single-scale dot integer-core typed "
                    "surface";
  // The bounded codebook decode family: iq4_nl (flat single fp16 scale, the FIRST
  // codebook sibling) and iq4_xs (the SUPER-BLOCK sibling riding the SAME brick with a
  // K-quant 6-bit SIGNED per-sub-block scale -- the enclosing loop op's fold_model
  // "codebook_superblock_signed6_no_min" + its scales_l/scales_h/n_subblocks attrs
  // discriminate it; the core brick carries the SAME 16-entry codebook).
  if (decodeModel != "iq4_nl" && decodeModel != "iq4_xs" &&
      decodeModel != "mxfp4")
    return err() << "only accepts decode_model \"iq4_nl\" (the flat non-linear "
                    "16-entry codebook repack), \"iq4_xs\" (the super-block "
                    "signed-6 sub-block-scale codebook repack), or \"mxfp4\" (the "
                    "flat doubled-e2m1 codebook + E8M0 shared-exponent scale repack); "
                    "got \""
                 << decodeModel << "\"";
  if (codebook.size() != 16)
    return err() << "requires a 16-entry non-linear int8 codebook (the kvalues "
                    "lookup range [0,15]) for the bounded codebook repack core; "
                    "got "
                 << codebook.size() << " entries";
  if (coreLmul.has_value() && *coreLmul != "mf2" && *coreLmul != "m1")
    return err() << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 "
                    "fractional chain) or \"m1\" (the RVV0.7 whole-LMUL chain); "
                    "got \""
                 << *coreLmul << "\"";
  return mlir::success();
}

mlir::LogicalResult RepackGemvCodebookCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackCodebookCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemv_codebook_core",
          getKind(), getDecodeModel(), getCodebook(), getIntegerCoreLmul())))
    return mlir::failure();

  if (op->getNumOperands() != 4 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked block_iq4_nlx16 weight base, the plain "
              "block_q8_0 activation base, one !weft_rvv.vl operand, one "
              "block_index induction operand, and one or more per-strip i32 "
              "vector results (one per disjoint strip -- numHalves total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-strip result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-strip combined codebook sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-strip results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise codebook single-scale core";
  return mlir::success();
}

mlir::LogicalResult RepackGemmCodebookCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackCodebookCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemm_codebook_core",
          getKind(), getDecodeModel(), getCodebook(), getIntegerCoreLmul())))
    return mlir::failure();

  if (op->getNumOperands() != 5 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked block_iq4_nlx16 weight base, the interleaved "
              "block_q8_0x4 activation base, one !weft_rvv.vl operand, one "
              "block_index induction operand, one strip_row_offset operand, and "
              "one or more per-column i32 vector results (columnsPerPass total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  if (!llvm::isa<mlir::IndexType>(getStripRowOffset().getType()))
    return emitOpError()
           << "requires the strip_row_offset operand to be index-typed (the "
              "runtime strip row offset, region argument 1)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-column result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-column combined codebook sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-column results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise codebook single-scale core";
  return mlir::success();
}

// The SHARED grid-core (iq2 GRID CODEBOOK + SIGN-PLANE) bounded-surface verifier: pins
// the closed attr set, the kind, the decode_model family, the positive byte offsets, and
// the optional integer_core_lmul knob. The FIXED grid + signs64 planes are DERIVED static
// const tables (NEVER op attrs), so -- unlike the codebook core -- there is NO array attr
// here (the signs64 op-attr blocker cannot recur).
static mlir::LogicalResult
verifyRepackGridCoreCommon(mlir::Operation *op,
                           const std::function<mlir::InFlightDiagnostic()> &err,
                           llvm::StringRef expectedKind, llvm::StringRef kindGot,
                           llvm::StringRef decodeModel,
                           std::optional<llvm::StringRef> coreLmul) {
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "decode_model" ||
           name == "weight_quant_byte_offset" ||
           name == "weight_ls_byte_offset" ||
           name == "weight_sign_byte_offset" ||
           name == "activation_quant_byte_offset" || name == "n_subblocks" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return err()
             << "does not accept attribute '" << attr.getName()
             << "'; the grid repack core keeps SEW/LMUL/policy on setvl/with_vl "
                "and runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";
    if (!isAllowedAttr(attrName))
      return err() << "only accepts the bounded grid repack core attributes "
                      "'kind', 'decode_model', 'weight_quant_byte_offset', "
                      "'weight_ls_byte_offset', 'weight_sign_byte_offset', "
                      "'activation_quant_byte_offset', 'n_subblocks', and "
                      "'integer_core_lmul'; unexpected attribute '"
                   << attr.getName() << "'";
  }
  if (kindGot != expectedKind)
    return err() << "currently supports only kind \"" << expectedKind
                 << "\" for the bounded grid 16x1-repacked per-block lane-wise "
                    "dual memory-gather ls-scale dot integer-core typed surface";
  // The bounded grid decode family is the CLOSED weft::GridDecodePlan registry
  // (Weft/Support/GridDecodePlan.h) -- the SAME authority the repack GEVM/GEMM emitter
  // leaves consult, replacing what used to be THREE hand-synced copies of this string
  // chain. Fail-closed ([D-1] unknown = reject) is preserved BY CONSTRUCTION: an
  // unregistered decode_model has no plan, so it is rejected here. The FIXED grid +
  // signs planes stay DERIVED static const (NEVER op attrs); the plan NAMES them.
  if (!weft::lookupGridDecodePlan(decodeModel)) {
    // Render the accepted set FROM the registry so the diagnostic can never drift
    // from what is actually legal.
    std::string accepted;
    llvm::raw_string_ostream acceptedOS(accepted);
    llvm::interleaveComma(weft::getGridDecodePlans(), acceptedOS,
                          [&](const weft::GridDecodePlan &plan) {
                            acceptedOS << '"' << plan.decodeModel << "\" ("
                                       << (plan.lsArity == weft::GridLsArity::Single
                                               ? "single-ls "
                                               : "dual-ls ")
                                       << plan.gridEntryCount << "-entry grid + "
                                       // A TernaryDelta row has NO sign table to
                                       // name (signArrayName is empty by
                                       // construction), so render its ACTUAL
                                       // decode shape rather than a blank.
                                       << (plan.signPlane ==
                                                   weft::GridSignPlane::TernaryDelta
                                               ? llvm::StringRef("ternary-delta")
                                               : plan.signArrayName)
                                       << ")";
                          });
    return err() << "only accepts a decode_model registered in the closed grid "
                    "decode plan registry -- "
                 << acceptedOS.str() << " repack; got \"" << decodeModel << "\"";
  }
  if (coreLmul.has_value() && *coreLmul != "mf2" && *coreLmul != "m1")
    return err() << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 "
                    "fractional chain) or \"m1\" (the RVV0.7 whole-LMUL chain); "
                    "got \""
                 << *coreLmul << "\"";
  return mlir::success();
}

mlir::LogicalResult RepackGemvGridCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackGridCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemv_grid_core", getKind(),
          getDecodeModel(), getIntegerCoreLmul())))
    return mlir::failure();

  if (getWeightQuantByteOffsetAttr().getInt() <= 0 ||
      getWeightLsByteOffsetAttr().getInt() <= 0 ||
      getWeightSignByteOffsetAttr().getInt() <= 0 ||
      getActivationQuantByteOffsetAttr().getInt() <= 0 ||
      getNSubblocksAttr().getInt() <= 0)
    return emitOpError()
           << "requires positive grid-index / ls-scale / sign-selector / "
              "activation-quant byte offsets and n_subblocks (the iq2_xxs "
              "block decode plane locations + sub-block count)";

  if (op->getNumOperands() != 4 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked block_iq2_xxsx16 weight base, the plain "
              "block_q8_K activation base, one !weft_rvv.vl operand, one "
              "block_index induction operand, and one or more per-strip i32 "
              "vector results (one per disjoint strip -- numHalves total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-strip result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-strip combined grid sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-strip results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise grid ls-scale core";
  return mlir::success();
}

mlir::LogicalResult RepackGemmGridCoreOp::verify() {
  mlir::Operation *op = getOperation();
  if (mlir::failed(verifyRepackGridCoreCommon(
          op, [&]() { return emitOpError(); }, "repack_gemm_grid_core", getKind(),
          getDecodeModel(), getIntegerCoreLmul())))
    return mlir::failure();

  if (getWeightQuantByteOffsetAttr().getInt() <= 0 ||
      getWeightLsByteOffsetAttr().getInt() <= 0 ||
      getWeightSignByteOffsetAttr().getInt() <= 0 ||
      getActivationQuantByteOffsetAttr().getInt() <= 0 ||
      getNSubblocksAttr().getInt() <= 0)
    return emitOpError()
           << "requires positive grid-index / ls-scale / sign-selector / "
              "activation-quant byte offsets and n_subblocks (the iq2_xxs "
              "block decode plane locations + sub-block count)";

  if (op->getNumOperands() != 5 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked block_iq2_xxsx16 weight base, the "
              "interleaved block_q8_Kx4 activation base, one !weft_rvv.vl operand, "
              "one block_index induction operand, one strip_row_offset operand, "
              "and one or more per-column i32 vector results (columnsPerPass total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  if (!llvm::isa<mlir::IndexType>(getStripRowOffset().getType()))
    return emitOpError()
           << "requires the strip_row_offset operand to be index-typed (the "
              "runtime strip row offset, region argument 1)";
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-column result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-column combined grid sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-column results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked lane-wise grid ls-scale core";
  return mlir::success();
}

// NOTE (G3 主线A T3 format4): GgmlRepackGemvQ5KQ8KOp::verify() +
// GgmlRepackGemmQ5KQ8KOp::verify() are RETIRED with the q5_K K-quant super-block
// monolith direct-emitter ops (the FIFTH K-quant super-block retired to the front
// door, the THIRD min-fold K-quant, COMPLETING the K-quant repack family). The q5_K
// repack GEVM/GEMM now flow through the typed_repack_gem{v,m}_loop_body front door: the
// shared K-quant core brick (RepackGem{v,m}KQuantCoreOp::verify,
// verifyRepackKQuantCoreCommon) accepts decode_model "q5_K" (5-bit nibble + qh-5th-bit
// dual-scale + bsums-min) alongside "q4_K"/"q2_K" (min-fold) and "q6_K"/"q3_K" (no-min),
// and the abstract GgmlQuantContractionOp::verify (above) pins the PLAIN block_q5_K
// fact-set (stride 176, qs @48, qh @16) fail-closed. q5_K REUSES the q4_K
// "kquant_dmin_bsums_min" min fold (hasMin) WHOLE -- the ONLY loop-body change is that
// the qh SECOND weight-plane attr (weight_qh_byte_offset, the SHARED slot q6_K/q3_K use
// on the no-min fold) is now ALSO accepted on the min fold (q5_K = q4_K min fold + the
// qh 5th-bit plane).

// NOTE (G3 主线A T3 format3): GgmlRepackGemvQ3KQ8KOp::verify() +
// GgmlRepackGemmQ3KQ8KOp::verify() are RETIRED with the q3_K K-quant super-block
// monolith direct-emitter ops (the SECOND no-min K-quant super-block, the LAST
// K-quant repack sibling retired to the front door). The q3_K repack GEVM/GEMM now
// flow through the typed_repack_gem{v,m}_loop_body front door: the shared K-quant core
// brick (RepackGem{v,m}KQuantCoreOp::verify, verifyRepackKQuantCoreCommon) accepts
// decode_model "q3_K" (3-bit subtractive-hmask single-accumulator no-min) alongside
// "q4_K"/"q2_K" (min-fold) and "q6_K" (6-bit no-min), and the abstract
// GgmlQuantContractionOp::verify (above) pins the PLAIN block_q3_K fact-set (stride
// 110, hmask @0) fail-closed. q3_K REUSES the q6_K "kquant_single_scale_no_min" fold
// (hasMin=false); its hmask SECOND weight plane rides the SHARED weight_qh_byte_offset
// loop-body attr (the same slot q6_K's qh high-2-bit plane uses) -- NO new loop-body
// fold gating.

// NOTE (G3 主线A T3 format2): GgmlRepackGemvQ2KQ8KOp::verify() +
// GgmlRepackGemmQ2KQ8KOp::verify() are RETIRED with the q2_K K-quant super-block
// monolith direct-emitter ops (the THIRD K-quant super-block retired to the front
// door, the SECOND min-fold K-quant). The q2_K repack GEVM/GEMM now flow through the
// typed_repack_gem{v,m}_loop_body front door: the shared K-quant core brick
// (RepackGem{v,m}KQuantCoreOp::verify, verifyRepackKQuantCoreCommon) accepts
// decode_model "q2_K" (2-bit dual-scale + bsums-min) alongside "q4_K" (4-bit) and
// "q6_K" (6-bit no-min), and the abstract GgmlQuantContractionOp::verify (above)
// pins the PLAIN block_q2_K fact-set (stride 84, qs @16) fail-closed. q2_K REUSES the
// q4_K "kquant_dmin_bsums_min" fold (hasMin) -- NO new loop-body fold gating.

// NOTE: GgmlRepackGemvTQ10Q8KOp::verify() + GgmlRepackGemmTQ10Q8KOp::verify() are
// RETIRED with the tq1_0 BASE-3 TERNARY monolith direct-emitter ops (G3 主线B batch2,
// the ternary-batch COMPLETION). The tq1_0 repack GEVM/GEMM now flow through the
// typed_repack_gem{v,m}_loop_body front door: the shared ternary core brick
// (RepackGem{v,m}TernaryCoreOp::verify, verifyRepackTernaryCoreCommon) already accepts
// decode_model "tq1_0" (base-3) alongside "tq2_0" (2-bit), and the abstract
// GgmlQuantContractionOp::verify (below) pins the PLAIN block_tq1_0 fact-set
// fail-closed. The base-3 qh SECOND-plane offset rides on the loop body op's OPTIONAL
// weight_qh_byte_offset attr.

// NOTE (G3 M2 iq4_nl codebook front-door): GgmlRepackGemvIq4NlQ80Op::verify() +
// GgmlRepackGemmIq4NlQ80Op::verify() are RETIRED with the iq4_nl FLAT CODEBOOK monolith
// direct-emitter ops (the FIRST codebook decode family retired to the front door). The
// iq4_nl repack GEVM/GEMM now flow through the typed_repack_gem{v,m}_loop_body front
// door: the SHARED codebook core brick (RepackGem{v,m}CodebookCoreOp::verify,
// verifyRepackCodebookCoreCommon) accepts decode_model "iq4_nl" + the 16-entry non-linear
// int8 codebook, and the abstract GgmlQuantContractionOp::verify (above) pins the PLAIN
// block_iq4_nl fact-set (stride 18, nibbles @2, q8 high half @16) fail-closed. iq4_nl
// carries the new "codebook_flat_single_scale" fold; the 16-entry codebook rides the core
// brick's DenseI8ArrayAttr (a load-bearing WHAT the MEMORY vluxei16 gather indexes).

// NOTE (G3 retirement_batch 4 mxfp4 codebook front-door): GgmlRepackGemvMxfp4Q8Op::verify()
// + GgmlRepackGemmMxfp4Q8Op::verify() are RETIRED with the mxfp4 FLAT CODEBOOK + E8M0
// monolith op-defs (the LAST dispatch-wired repack cell, retirement_batch 4). The
// weft_rvv.repack_gem{v,m}_codebook_core verifier (verifyRepackCodebookCoreCommon) accepts
// decode_model "mxfp4" + the 16-entry doubled-e2m1 codebook, the loop-body verifier accepts
// the "codebook_flat_e8m0_scale" fold, and the abstract GgmlQuantContractionOp::verify pins
// the PLAIN block_mxfp4 fact-set (stride 17, nibbles @1 after the E8M0 exponent byte, q8 high
// half @16) fail-closed. The E8M0 shared-exponent scale + doubled-e2m1 codebook ride the SAME
// codebook core brick iq4_nl/iq4_xs use, keyed off decode_model "mxfp4".

// NOTE (G3 M2-后 iq4_xs codebook front-door): GgmlRepackGemvIq4XsQ8KOp::verify() +
// GgmlRepackGemmIq4XsQ8KOp::verify() are RETIRED with the iq4_xs SUPER-BLOCK CODEBOOK
// monolith op-defs (the SECOND codebook decode family retired to the typed-region
// front door, COMPLETING the iq4 codebook pair with iq4_nl). The iq4_xs repack now
// flows through the typed_repack_gem{v,m}_loop_body front door (fold_model
// "codebook_superblock_signed6_no_min") carrying the SHARED repack_gem{v,m}_codebook_core
// brick (decode_model "iq4_xs" -- verifyRepackCodebookCoreCommon widened to accept it
// alongside "iq4_nl"; the SAME 16-entry non-linear int8 codebook). The K-quant-style
// 6-bit SIGNED per-sub-block scale facts (scales_l LOW pair @64, scales_h HIGH 2-bit @32,
// n_subblocks 8) ride on the loop body op's OPTIONAL super-block attrs
// (weight_scales_byte_offset / weight_scales_high_byte_offset / n_subblocks); the
// abstract quant_contraction fact-set (block_iq4_xs stride 136, nibbles @8, q8_K
// activation) is validated by GgmlQuantContractionOp::verify's codebook super-block branch.

// NOTE (G3 M4 iq2-grid front-door, first cell iq2_xxs): GgmlRepackGemvIq2XxsQ8KOp::verify()
// + GgmlRepackGemmIq2XxsQ8KOp::verify() are RETIRED with the iq2_xxs GRID CODEBOOK +
// SIGN-PLANE monolith direct-emitter ops (the FIRST grid decode family retired to the
// typed-region front door). The iq2_xxs repack GEVM/GEMM now flow through the
// typed_repack_gem{v,m}_loop_body front door: the NEW grid core brick
// (RepackGem{v,m}GridCoreOp::verify, verifyRepackGridCoreCommon) accepts decode_model
// "iq2_xxs" (single ls-scale, u8 grid index, DERIVED signs64 plane), and the loop body
// verifier (TypedRepackGem{v,m}LoopBodyOp::verify) accepts fold_model
// "grid_sign_single_scale_eighth". The FIXED 256-entry grid + signs64 planes stay DERIVED
// static const tables (NEVER op attrs); the grid/ls/sign byte offsets + n_subblocks ride
// on the grid core brick.

// NOTE (G3 M4 iq2-grid front-door, cells iq2_xs + iq2_s): GgmlRepackGemvIq2XsQ8KOp::verify()
// + GgmlRepackGemmIq2XsQ8KOp::verify() + GgmlRepackGemvIq2SQ8KOp::verify() +
// GgmlRepackGemmIq2SQ8KOp::verify() are RETIRED with the iq2_xs / iq2_s DUAL-scale GRID
// CODEBOOK + SIGN-PLANE monolith direct-emitter ops (the DUAL-ls grid decode siblings of
// iq2_xxs, COMPLETING the iq2 grid family). Both repacks now flow through the
// typed_repack_gem{v,m}_loop_body front door: the SHARED grid core brick
// (RepackGem{v,m}GridCoreOp::verify, verifyRepackGridCoreCommon) accepts decode_model
// "iq2_xs" (dual ls-scale, u16 grid index, DERIVED signs64 plane) / "iq2_s" (dual ls-scale,
// u16 assembled grid index, DIRECT signs256 plane), and the loop body verifier
// (TypedRepackGem{v,m}LoopBodyOp::verify) accepts fold_model "grid_sign_dualscale_eighth".
// The FIXED iq2xs_grid (512) + signs64 / iq2s_grid (1024) + signs256 planes stay DERIVED
// static const tables (NEVER op attrs); the dual grid/ls/sign byte offsets + n_subblocks
// ride on the grid core brick. The iq2 grid family is now COMPLETE at the front door.

mlir::LogicalResult GgmlRepackGemvQ41Q81Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16-plus-min scale model, and the 16x1 REPACKED block-format
  // structural facts (including the SECOND-scale byte offsets the q4_0 sibling
  // has no need for). Anything else -- a forbidden local element_count/SEW/LMUL/
  // policy attr, or an unexpected name -- is rejected fail-closed (I7). The
  // runtime nc count is a RUNTIME ABI value operand; there is NO nr/bs (GEMV is
  // single-column).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "weight_min_byte_offset" ||
           name == "activation_sum_byte_offset" ||
           name == "weight_interleave" || name == "half_lanes" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemv_q4_1_q8_1 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/nc in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q4_1 x Q8_1 16x1-repacked GEMV "
                "attributes 'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'weight_min_byte_offset', "
                "'activation_sum_byte_offset', 'weight_interleave', "
                "'half_lanes', and 'integer_core_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_repack_gemv_q4_1_q8_1")
    return emitOpError()
           << "currently supports only kind \"ggml_repack_gemv_q4_1_q8_1\" for "
              "the bounded ggml Q4_1 x Q8_1 16x1-repacked GEMV typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y-plus-min")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y-plus-min\" "
              "for the ggml Q4_1 x Q8_1 16x1-repacked GEMV route";

  // The 16x1 repacked q4_1 decode ABI (pinned fail-closed I7): QK == 32,
  // block_q4_1x16 weight stride 320 (16 inline fp16 d + 16 inline fp16 m + 256
  // interleaved nibble bytes), block_q8_1 activation stride 36 (fp16 d + fp16 s
  // + 32 int8 quants -- the PLAIN q8_1 stream, NOT an interleaved x4), weight
  // quants at byte offset +64 (after the 16 d + 16 m fp16 scales), the per-row
  // MIN strip at byte offset +32 (after the 16 d scales), activation quants at
  // byte offset +4 (after the d + s fp16 scales), the activation scaled-sum at
  // byte offset +2 (after d), 16 weight rows per group, and the VLEN-derived
  // half-lane split width.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_1) for the ggml Q4_1 x Q8_1 "
                            "16x1-repacked GEMV route";
  if (getWeightBlockStride() != 320)
    return emitOpError()
           << "requires weight_block_stride == 320 (sizeof block_q4_1x16: 16 "
              "fp16 d + 16 fp16 m + 256 nibble bytes) for the ggml Q4_1 x Q8_1 "
              "16x1-repacked GEMV route";
  if (getActivationBlockStride() != 36)
    return emitOpError()
           << "requires activation_block_stride == 36 (sizeof block_q8_1, the "
              "plain single-column q8_1 activation stream) for the ggml Q4_1 x "
              "Q8_1 16x1-repacked GEMV route";
  if (getWeightQuantByteOffset() != 64)
    return emitOpError()
           << "requires weight_quant_byte_offset == 64 (the 16 inline fp16 d + "
              "16 inline fp16 m scales precede the interleaved nibble bytes) for "
              "the ggml Q4_1 x Q8_1 16x1-repacked GEMV route";
  if (getWeightMinByteOffset() != 32)
    return emitOpError()
           << "requires weight_min_byte_offset == 32 (the 16 per-row fp16 MIN m "
              "strip follows the 16 inline fp16 delta d scales) for the ggml "
              "Q4_1 x Q8_1 16x1-repacked GEMV route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (the d + s inline fp16 "
              "scales precede the int8 quants) for the ggml Q4_1 x Q8_1 "
              "16x1-repacked GEMV route";
  if (getActivationSumByteOffset() != 2)
    return emitOpError()
           << "requires activation_sum_byte_offset == 2 (the block_q8_1 scaled "
              "sum s follows the inline fp16 delta d) for the ggml Q4_1 x Q8_1 "
              "16x1-repacked GEMV route";
  if (getWeightInterleave() != 16)
    return emitOpError() << "requires weight_interleave == 16 (the 16x1 "
                            "block-as-lane repack width) for the ggml Q4_1 x "
                            "Q8_1 16x1-repacked GEMV route";
  // half_lanes is the resource-aware e16m1 strip width: 8 at VLEN=128 (two
  // disjoint 8-lane halves), 16 at VLEN=256 (one 16-lane strip). It MUST divide
  // the 16-way interleave; a 16-lane strip reads byte-identical repacked data to
  // two 8-lane halves. Any other width (e.g. 12) is rejected fail-closed (I7).
  if (getHalfLanes() != 8 && getHalfLanes() != 16)
    return emitOpError()
           << "requires half_lanes in {8, 16} (the resource-aware e16m1 strip "
              "width: 8 at VLEN=128 -> two 8-lane halves, 16 at VLEN=256 -> one "
              "16-lane strip) for the ggml Q4_1 x Q8_1 16x1-repacked GEMV route";
  if (getWeightInterleave() % getHalfLanes() != 0)
    return emitOpError()
           << "requires half_lanes to divide weight_interleave (16) so the "
              "16-block-as-lane group tiles into whole strips for the ggml Q4_1 "
              "x Q8_1 16x1-repacked GEMV route";

  // The optional integer_core_lmul anchors the per-strip integer-product chain
  // (the *how*, never the *what*). Only two anchors are legal, each pinned to
  // its strip width fail-closed (I7): absent / "mf2" (the RVV1.0 fractional
  // chain), or "m1" (the RVV0.7.1 whole-LMUL chain, ONE 16-lane strip so
  // half_lanes MUST be 16).
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "requires integer_core_lmul in {\"mf2\", \"m1\"} (the RVV1.0 "
                "fractional core anchor or the RVV0.7.1 whole-LMUL core anchor) "
                "for the ggml Q4_1 x Q8_1 16x1-repacked GEMV route; got \""
             << coreLmul << "\"";
    if (coreLmul == "m1" && getHalfLanes() != 16)
      return emitOpError()
             << "requires half_lanes == 16 when integer_core_lmul is \"m1\" "
                "(the whole-LMUL i8m1 strip is 16 i8 lanes, tiling the "
                "16-block-as-lane group into exactly ONE 16-lane strip) for the "
                "ggml Q4_1 x Q8_1 16x1-repacked GEMV route";
  }

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one repacked weight base pointer, one plain activation "
              "base pointer, one output pointer, one runtime element-count, one "
              "runtime column-count, one !weft_rvv.vl operand, and one i32 LMUL "
              "m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_1x16 repacked weight "
              "byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_1 plain "
              "activation byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, nc outputs)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of weight columns)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q4_1 x Q8_1 16x1-repacked GEMV route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q4_1 x Q8_1 16x1-repacked GEMV";

  return mlir::success();
}

mlir::LogicalResult GgmlRepackGemmQ41Q81Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // dual-fp16-plus-min scale model, and the 16x1 REPACKED block-format structural
  // facts (including the SECOND-scale byte offsets the q4_0 GEMM has no need for).
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7). The runtime nr/nc counts and
  // the output row stride are RUNTIME ABI value operands.
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "weight_min_byte_offset" ||
           name == "activation_sum_byte_offset" ||
           name == "weight_interleave" || name == "activation_interleave" ||
           name == "half_lanes" || name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemm_q4_1_q8_1 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/nr/nc/bs in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded ggml Q4_1 x Q8_1 16x1-repacked GEMM "
                "attributes 'kind', 'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'weight_min_byte_offset', "
                "'activation_sum_byte_offset', 'weight_interleave', "
                "'activation_interleave', 'half_lanes', and 'integer_core_lmul'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_repack_gemm_q4_1_q8_1")
    return emitOpError()
           << "currently supports only kind \"ggml_repack_gemm_q4_1_q8_1\" for "
              "the bounded ggml Q4_1 x Q8_1 16x1-repacked GEMM typed surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y-plus-min")
    return emitOpError()
           << "requires scale_model \"dual-fp16-per-block-d_x.d_y-plus-min\" "
              "for the ggml Q4_1 x Q8_1 16x1-repacked GEMM route";

  // The 16x1 repacked q4_1 GEMM ABI (pinned fail-closed I7): QK == 32,
  // block_q4_1x16 weight stride 320 (16 d + 16 m fp16 + 256 nibble bytes),
  // block_q8_1x4 activation stride 144 (4 d + 4 s fp16 + 128 int8 quants), weight
  // quants at +64 (after the 16 d + 16 m scales), the per-row MIN strip at +32
  // (after the 16 d scales), activation quants at +16 (after the 4 d + 4 s
  // scales), the per-column activation scaled-sum at +8 (after the 4 d scales),
  // 16 weight rows / 4 activation columns per group, and the VLEN-derived
  // half-lane split width.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK8_1) for the ggml Q4_1 x Q8_1 "
                            "16x1-repacked GEMM route";
  if (getWeightBlockStride() != 320)
    return emitOpError()
           << "requires weight_block_stride == 320 (sizeof block_q4_1x16: 16 "
              "fp16 d + 16 fp16 m + 256 nibble bytes) for the ggml Q4_1 x Q8_1 "
              "16x1-repacked GEMM route";
  if (getActivationBlockStride() != 144)
    return emitOpError()
           << "requires activation_block_stride == 144 (sizeof block_q8_1x4: 4 "
              "fp16 d + 4 fp16 s + 128 int8 quants) for the ggml Q4_1 x Q8_1 "
              "16x1-repacked GEMM route";
  if (getWeightQuantByteOffset() != 64)
    return emitOpError()
           << "requires weight_quant_byte_offset == 64 (the 16 inline fp16 d + "
              "16 inline fp16 m scales precede the interleaved nibble bytes) for "
              "the ggml Q4_1 x Q8_1 16x1-repacked GEMM route";
  if (getActivationQuantByteOffset() != 16)
    return emitOpError()
           << "requires activation_quant_byte_offset == 16 (the 4 d + 4 s inline "
              "fp16 scales precede the interleaved int8 quants) for the ggml Q4_1 "
              "x Q8_1 16x1-repacked GEMM route";
  if (getWeightMinByteOffset() != 32)
    return emitOpError()
           << "requires weight_min_byte_offset == 32 (the 16 per-row fp16 MIN m "
              "strip follows the 16 inline fp16 delta d scales) for the ggml "
              "Q4_1 x Q8_1 16x1-repacked GEMM route";
  if (getActivationSumByteOffset() != 8)
    return emitOpError()
           << "requires activation_sum_byte_offset == 8 (the 4 per-column "
              "block_q8_1x4 scaled sums s follow the 4 inline fp16 delta d) for "
              "the ggml Q4_1 x Q8_1 16x1-repacked GEMM route";
  if (getWeightInterleave() != 16)
    return emitOpError() << "requires weight_interleave == 16 (the 16x1 "
                            "block-as-lane repack width) for the ggml Q4_1 x "
                            "Q8_1 16x1-repacked GEMM route";
  if (getActivationInterleave() != 4)
    return emitOpError() << "requires activation_interleave == 4 (the q8_1x4 "
                            "activation-column group width) for the ggml Q4_1 x "
                            "Q8_1 16x1-repacked GEMM route";
  // half_lanes is the resource-aware e16m1 strip width: 8 at VLEN=128 (two
  // disjoint 8-lane halves), 16 at VLEN=256 (one 16-lane strip). It MUST divide
  // the 16-way interleave; a 16-lane strip reads byte-identical repacked data to
  // two 8-lane halves. Any other width (e.g. 12) is rejected fail-closed (I7).
  if (getHalfLanes() != 8 && getHalfLanes() != 16)
    return emitOpError()
           << "requires half_lanes in {8, 16} (the resource-aware e16m1 strip "
              "width: 8 at VLEN=128 -> two 8-lane halves, 16 at VLEN=256 -> one "
              "16-lane strip) for the ggml Q4_1 x Q8_1 16x1-repacked GEMM route";
  if (getWeightInterleave() % getHalfLanes() != 0)
    return emitOpError()
           << "requires half_lanes to divide weight_interleave (16) so the "
              "16-block-as-lane group tiles into whole strips for the ggml Q4_1 "
              "x Q8_1 16x1-repacked GEMM route";

  // The optional integer_core_lmul anchors the per-strip integer-product chain
  // (the *how*, never the *what*). Only two anchors are legal, each pinned to
  // its strip width fail-closed (I7): absent / "mf2" (the RVV1.0 fractional
  // chain), or "m1" (the RVV0.7.1 whole-LMUL chain, ONE 16-lane strip so
  // half_lanes MUST be 16).
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "requires integer_core_lmul in {\"mf2\", \"m1\"} (the RVV1.0 "
                "fractional core anchor or the RVV0.7.1 whole-LMUL core anchor) "
                "for the ggml Q4_1 x Q8_1 16x1-repacked GEMM route; got \""
             << coreLmul << "\"";
    if (coreLmul == "m1" && getHalfLanes() != 16)
      return emitOpError()
             << "requires half_lanes == 16 when integer_core_lmul is \"m1\" "
                "(the whole-LMUL i8m1 strip is 16 i8 lanes, tiling the "
                "16-block-as-lane group into exactly ONE 16-lane strip) for the "
                "ggml Q4_1 x Q8_1 16x1-repacked GEMM route";
  }

  if (op->getNumOperands() != 8 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one repacked weight base pointer, one repacked "
              "activation base pointer, one output pointer, one runtime "
              "element-count, one runtime row-count, one runtime column-count, "
              "one output-row float-stride runtime ABI operand, one "
              "!weft_rvv.vl operand, and one i32 LMUL m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_1x16 repacked weight "
              "byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_1x4 repacked "
              "activation byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination, nr x nc outputs)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getRowCount().getType()))
    return emitOpError()
           << "requires the row-count operand to be a runtime index value (nr, "
              "the number of activation rows)";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be a runtime index value "
              "(nc, the number of weight columns)";
  if (!llvm::isa<mlir::IndexType>(getOutputRowStride().getType()))
    return emitOpError()
           << "requires the output-row-stride operand to be a runtime index "
              "value (bs, the per-output-row float stride)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q4_1 x Q8_1 16x1-repacked GEMM route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q4_1 x Q8_1 16x1-repacked GEMM";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotMXFP4Q80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // E8M0 shared-exponent weight scale model, the block-format structural facts,
  // the 16-entry non-linear int8 CODEBOOK (a structural fact, like the
  // strides/offsets), and the bounded shape knobs. Anything else -- a forbidden
  // local element_count/SEW/LMUL/policy attr, or an unexpected name -- is
  // rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "activation_high_byte_offset" || name == "codebook" ||
           name == "integer_core_lmul" || name == "multi_block_factor" ||
           name == "strip_elision" || name == "minimum_vlen" ||
           name == "weft_rvv.flat_decode_primitive" ||
           name == "weft_rvv.flat_fold_model" ||
           name == "weft_rvv.flat_block_length" ||
           name == "weft_rvv.flat_activation_quant_byte_offset" ||
           name == "weft_rvv.flat_weight_scale_source" ||
           name == "weft_rvv.flat_codebook_table_name" ||
           name == "weft_rvv.flat_body_family" ||
           name == "weft_rvv.flat_offset_bias";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.mxfp4_q8_0_block_dot keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded block dot-product attributes 'kind', "
                "'scale_model', 'qk', 'weight_block_stride', "
                "'activation_block_stride', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'activation_high_byte_offset', "
                "and 'codebook'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_mxfp4_q8_0_block_dot")
    return emitOpError()
           << "currently supports only kind \"ggml_mxfp4_q8_0_block_dot\" for "
              "the bounded ggml MXFP4 x Q8_0 block dot-product typed surface";
  // The E8M0 half-form scale convention is the load-bearing distinction between
  // mxfp4 and iq4_nl (the codebook is the DOUBLED int8 e2m1 set, so the block
  // scale is 2^(e-128), the HALF form). Pin it so a wrong scale convention (the
  // full 2^(e-127), which would double every result) is rejected fail-closed.
  if (getScaleModel() != "e8m0-half-shared-exponent-per-block")
    return emitOpError()
           << "requires scale_model \"e8m0-half-shared-exponent-per-block\" "
              "for the ggml MXFP4 x Q8_0 block dot-product route (the E8M0 "
              "2^(e-128) half form matching the doubled int8 e2m1 codebook)";
  // ggml's externally-defined block format (ggml-common.h): QK_MXFP4 == QK8_0 ==
  // 32, block_mxfp4 = { uint8_t e; uint8_t qs[16] } stride 17 (NOT 18: a single
  // 8-bit E8M0 exponent, NOT a fp16 d), block_q8_0 stride 34, the weight nibbles
  // at byte offset +1 (after the 1-byte exponent), the q8 quants at +2, the q8
  // high half at +16. Pin them so a malformed typed body cannot lower under the
  // block-dot emission.
  if (getQk() != 32)
    return emitOpError() << "requires qk == 32 (QK_MXFP4 == QK8_0) for the ggml "
                            "MXFP4 x Q8_0 block dot-product route";
  if (getWeightBlockStride() != 17)
    return emitOpError()
           << "requires weight_block_stride == 17 (sizeof block_mxfp4: one "
              "E8M0 exponent byte + 16 packed FP4 nibble bytes) for the ggml "
              "MXFP4 x Q8_0 block dot-product route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
              "the ggml MXFP4 x Q8_0 block dot-product route";
  if (getWeightQuantByteOffset() != 1)
    return emitOpError()
           << "requires weight_quant_byte_offset == 1 (the FP4 nibbles follow "
              "the single E8M0 exponent byte) for the ggml MXFP4 x Q8_0 block "
              "dot-product route";
  if (getActivationQuantByteOffset() != 2)
    return emitOpError()
           << "requires activation_quant_byte_offset == 2 (the q8 quants follow "
              "the inline fp16 scale) for the ggml MXFP4 x Q8_0 block "
              "dot-product route";
  if (getActivationHighByteOffset() != 16)
    return emitOpError()
           << "requires activation_high_byte_offset == 16 (q8 high half) for "
              "the ggml MXFP4 x Q8_0 block dot-product route";

  // The codebook is the load-bearing structural fact of the codebook class: it
  // MUST carry EXACTLY 16 int8 entries (one per FP4 nibble index [0,15]). A wrong
  // size cannot index the nibbles and is rejected fail-closed (I7). The entry
  // VALUES are NOT pinned here -- they are a genuine structural input the gather
  // realizes (a wrong-but-well-sized codebook is a legal-but-different kernel,
  // which is exactly what the negative-control validation exercises).
  if (getCodebook().size() != 16)
    return emitOpError()
           << "requires codebook to carry exactly 16 int8 entries (the FP4 "
              "e2m1 nibble->int8 lookup table kvalues_mxfp4[16]); got "
           << getCodebook().size();

  // The source form may be wholly unscheduled before formula construction. Once
  // any final schedule field is present, the plan must be structurally atomic.
  unsigned scheduleFields = static_cast<bool>(getIntegerCoreLmul()) +
                            static_cast<bool>(getMultiBlockFactor()) +
                            static_cast<bool>(getStripElision()) +
                            static_cast<bool>(getMinimumVlen());
  if (scheduleFields != 0 && scheduleFields != 4)
    return emitOpError()
           << "requires integer_core_lmul, multi_block_factor, strip_elision, "
              "and minimum_vlen to be all absent or all present";
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul())
    if (*coreLmul != "m1" && *coreLmul != "mf2")
      return emitOpError()
             << "only accepts integer_core_lmul \"m1\" or \"mf2\"; got \""
             << *coreLmul << "\"";

  // The optional multi_block_factor is a bounded resource/scheduling shape knob:
  // 1 (default), 2, or 4 blocks per outer iteration (byte-exact: the per-block
  // fp32 folds stay in strict ascending order). Any other count is rejected
  // fail-closed (I7).
  if (std::optional<std::int64_t> multiBlockFactor = getMultiBlockFactor())
    if (*multiBlockFactor != 1 && *multiBlockFactor != 2 &&
        *multiBlockFactor != 4)
      return emitOpError()
             << "only accepts multi_block_factor 1, 2, or 4 (the bounded "
                "byte-exact block-unroll factors for the ggml MXFP4 x Q8_0 block "
                "dot-product outer loop); got "
             << *multiBlockFactor;

  // The optional strip_elision is a bounded resource/scheduling shape knob: the
  // inner half-block strip loop is kept ("robust", default) or elided ("elided").
  // The codebook gather ALWAYS anchors at m1 (VLMAX >= 16); "elided" is correct
  // only at VLEN >= 128. Any other spelling is rejected fail-closed (I7).
  if (std::optional<llvm::StringRef> stripElision = getStripElision()) {
    if (*stripElision != "robust" && *stripElision != "elided")
      return emitOpError()
             << "only accepts strip_elision \"robust\" or \"elided\" (the "
                "bounded inner-strip-loop shape knobs for the ggml MXFP4 x Q8_0 "
                "block dot-product); got \""
             << *stripElision << "\"";
  }

  if (op->getNumOperands() != 5 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one output pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, and one i32 LMUL m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_mxfp4 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 byte "
              "array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml MXFP4 x Q8_0 block dot-product route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml MXFP4 x Q8_0 block dot-product";

  return mlir::success();
}

// NOTE: GgmlBlockDotNVFP4Q80Op::verify was RETIRED at the nvfp4 flip (C_construct
// 27->28) together with the monolith op def (see the RETIRED marker at the nvfp4
// slot in RVVOps.td; the removed verifier body lives in git history). The live
// bounded-surface gate is the nvfp4 codebook-core brick verifier
// (GgmlBlockDotNVFP4Q80CodebookCoreOp::verify, above). The retired monolith verifier
// body was PLAIN-REMOVED here (裁决九.4 retirement cleanup) rather than kept as a
// preprocessor-disabled dead-code tomb; see schema/monolith-retire-whitelist.v1.json
// (retired_ledger).

mlir::LogicalResult GgmlBlockDotQ10Q80BinarySignCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // binary-sign scale model, and the super-block-format structural facts (the
  // q1_0 stride, the q8_0 stride, the per-super-block q8-block span, and the two
  // quant byte offsets), plus the final resource shape knob integer_core_lmul +
  // semantic minimum_vlen. Anything else -- a forbidden local element_count/SEW/LMUL/policy
  // attr, or an unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "activation_blocks_per_weight" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul" || name == "minimum_vlen";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q1_0_q8_0_binary_sign_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded BINARY-sign block dot-product "
                "integer-core attributes 'kind', 'scale_model', 'qk', "
                "'weight_block_stride', 'activation_block_stride', "
                "'activation_blocks_per_weight', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'integer_core_lmul', and "
                "'minimum_vlen'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q1_0_q8_0_binary_sign_core")
    return emitOpError()
           << "currently supports only kind \"ggml_q1_0_q8_0_binary_sign_core\" "
              "for the bounded ggml Q1_0 x Q8_0 BINARY-sign scalar integer-core "
              "typed surface";
  // The binary-sign scale model is the load-bearing distinction of q1_0: each
  // weight bit is a SIGN (set -> +q8, clear -> -q8), the q8 value is the
  // magnitude (NO codebook, NO nibble unpack, NO offset-binary `-8` bias).
  if (getScaleModel() != "binary-sign-per-bit")
    return emitOpError()
           << "requires scale_model \"binary-sign-per-bit\" for the ggml Q1_0 x "
              "Q8_0 binary-sign integer-core route (a set bit -> +q8, a clear "
              "bit -> -q8; the q8 value is the magnitude)";
  // ggml's externally-defined super-block format (ggml-common.h): QK1_0 == 128,
  // block_q1_0 stride 18 (fp16 scale + 16 packed bit bytes), block_q8_0 stride
  // 34, ONE q1_0 super-block spanning FOUR q8_0 blocks, the weight bits at byte
  // offset +2, the q8 quants at +2.
  if (getQk() != 128)
    return emitOpError() << "requires qk == 128 (QK1_0) for the ggml Q1_0 x "
                            "Q8_0 binary-sign integer-core route";
  if (getWeightBlockStride() != 18)
    return emitOpError()
           << "requires weight_block_stride == 18 (sizeof block_q1_0: the fp16 "
              "scale + 16 packed bit bytes) for the ggml Q1_0 x Q8_0 "
              "binary-sign integer-core route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
              "the ggml Q1_0 x Q8_0 binary-sign integer-core route";
  if (getActivationBlocksPerWeight() != 4)
    return emitOpError()
           << "requires activation_blocks_per_weight == 4 (one 128-element q1_0 "
              "super-block spans four 32-element block_q8_0 activation blocks) "
              "for the ggml Q1_0 x Q8_0 binary-sign integer-core route";
  if (getWeightQuantByteOffset() != 2)
    return emitOpError()
           << "requires weight_quant_byte_offset == 2 (the packed bit bytes "
              "follow the inline fp16 scale) for the ggml Q1_0 x Q8_0 "
              "binary-sign integer-core route";
  if (getActivationQuantByteOffset() != 2)
    return emitOpError()
           << "requires activation_quant_byte_offset == 2 (the q8 quants follow "
              "the inline fp16 scale) for the ggml Q1_0 x Q8_0 binary-sign "
              "integer-core route";

  if (static_cast<bool>(getIntegerCoreLmul()) !=
      static_cast<bool>(getMinimumVlen()))
    return emitOpError()
           << "requires integer_core_lmul and minimum_vlen to be both absent "
              "or both present";
  if (std::optional<llvm::StringRef> anchor = getIntegerCoreLmul())
    if (*anchor != "m1" && *anchor != "m2")
      return emitOpError()
             << "only accepts integer_core_lmul \"m1\" or \"m2\"; got \""
             << *anchor << "\"";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (sumi placeholder) -- NO output pointer (the whole two-level fp32
  // fold + scalar store is emitter-inlined by the flat_binary_two_level loop
  // lowering, so this result is structurally-unused).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (sumi placeholder)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q1_0 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getSumi().getType().isInteger(32))
    return emitOpError()
           << "requires the result (sumi, the per-super-block binary-sign "
              "integer-dot placeholder) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q1_0 x Q8_0 binary-sign integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotQ6KQ8KAux32Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // per-sub-block int8 scale model, and the super-block-format structural facts.
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_qh_byte_offset" ||
           name == "weight_scales_byte_offset" ||
           name == "activation_quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q6_k_q8_k_aux32_partial keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded super-block dot-product attributes "
                "'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_qh_byte_offset', 'weight_scales_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q6_k_q8_k_aux32_partial")
    return emitOpError()
           << "currently supports only kind \"ggml_q6_k_q8_k_aux32_partial\" "
              "for the bounded ggml Q6_K x Q8_K super-block integer partial "
              "typed surface";
  if (getScaleModel() != "per-sub-block-int8-scale-i32-domain")
    return emitOpError()
           << "requires scale_model \"per-sub-block-int8-scale-i32-domain\" for "
              "the ggml Q6_K x Q8_K super-block integer partial route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 16 sub-blocks of 16 elements, block_q6_K stride 210 (ql@0|qh@128|scales@192|
  // d@208), block_q8_K stride 292 (d@0|qs@4|bsums@260). Pin them so a malformed
  // typed body cannot lower under the super-block partial emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml Q6_K x "
                            "Q8_K super-block integer partial route";
  if (getSubBlock() != 16)
    return emitOpError()
           << "requires sub_block == 16 (16-element sub-block scale boundary) "
              "for the ggml Q6_K x Q8_K super-block integer partial route";
  if (getWeightBlockStride() != 210)
    return emitOpError()
           << "requires weight_block_stride == 210 (sizeof block_q6_K) for the "
              "ggml Q6_K x Q8_K super-block integer partial route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml Q6_K x Q8_K super-block integer partial route";
  if (getWeightQhByteOffset() != 128)
    return emitOpError()
           << "requires weight_qh_byte_offset == 128 (qh follows ql[128]) for "
              "the ggml Q6_K x Q8_K super-block integer partial route";
  if (getWeightScalesByteOffset() != 192)
    return emitOpError()
           << "requires weight_scales_byte_offset == 192 (scales follow "
              "ql[128]+qh[64]) for the ggml Q6_K x Q8_K super-block integer "
              "partial route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml Q6_K x Q8_K super-block integer partial route";

  // M-FLAT q6_K milestone-1: the OPTIONAL loop-form `block_index` operand adds a
  // 6th operand (the per-super-block induction variable). Absent = the standalone
  // 5-operand single-super-block K1 form (byte-identical); present = the loop
  // form. block_index is ODS-typed Index, so no extra type check is needed here.
  unsigned expectedOperands = getBlockIndex() ? 6 : 5;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one aux32 output pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, an OPTIONAL `block_index` "
              "induction operand, and one i32 LMUL m1 result";

  // The three buffer operands and the element count are runtime ABI values; the
  // weight/activation bases address the AoS byte arrays as const uint8_t *, the
  // output is an int32_t * (the 8-lane aux32 integer-state destination -- NOT
  // the fp32 *s of the K2 fold), and the element count carries n.
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q6_K byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  // M-FLAT q6_K milestone-2 loop form: the int32_t aux32[8] scratch is a
  // function-scoped variable the super-block loop emitter DECLARES itself; in the
  // loop form (block_index present) it never reads this output slot (the aux8/
  // aux32 scratch is emitter-owned), so the slot is vestigial -- the front door
  // wires it to the weight ABI base to keep the exported ggml C signature the
  // exact 4-role n/s/vx/vy list. Only require its binding there; the standalone
  // single-super-block K1 form still pins the exact 'int32_t *' scratch type.
  if (!outputBinding)
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value";
  if (!getBlockIndex() && outputBinding.getCType() != "int32_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'int32_t *' (the per-super-block aux32[8] integer-state "
              "destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q6_K x Q8_K super-block integer partial "
              "route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q6_K x Q8_K super-block integer partial";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotQ3KQ8KAux32Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // per-sub-block signed 6-bit scale model, and the super-block-format structural
  // facts (the 32-byte high-bit plane hmask @0, the 64 packed 2-bit-weight qs @32,
  // the 12 packed 6-bit-signed-scale bytes scales @96, the q8_K qs @4). q3_K is
  // SYMMETRIC -- NO min, NO dmin, NO bsums. Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected
  // fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_hmask_byte_offset" ||
           name == "weight_qs_byte_offset" ||
           name == "weight_scales_byte_offset" ||
           name == "activation_quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q3_k_q8_k_aux32_partial keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded super-block dot-product attributes "
                "'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_hmask_byte_offset', 'weight_qs_byte_offset', "
                "'weight_scales_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q3_k_q8_k_aux32_partial")
    return emitOpError()
           << "currently supports only kind \"ggml_q3_k_q8_k_aux32_partial\" "
              "for the bounded ggml Q3_K x Q8_K super-block integer partial "
              "typed surface";
  if (getScaleModel() != "per-sub-block-int6-signed-scale-i32-domain")
    return emitOpError()
           << "requires scale_model \"per-sub-block-int6-signed-scale-i32-domain\" "
              "for the ggml Q3_K x Q8_K super-block integer partial route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 16 sub-blocks of 16 elements, block_q3_K stride 110 (hmask[32]@0|qs[64]@32|
  // scales[12]@96|d@108), block_q8_K stride 292 (d@0|qs@4|bsums@260). Pin them so
  // a malformed typed body cannot lower under the super-block partial emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml Q3_K x "
                            "Q8_K super-block integer partial route";
  if (getSubBlock() != 16)
    return emitOpError()
           << "requires sub_block == 16 (16-element sub-block scale boundary) "
              "for the ggml Q3_K x Q8_K super-block integer partial route";
  if (getWeightBlockStride() != 110)
    return emitOpError()
           << "requires weight_block_stride == 110 (sizeof block_q3_K) for the "
              "ggml Q3_K x Q8_K super-block integer partial route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml Q3_K x Q8_K super-block integer partial route";
  if (getWeightHmaskByteOffset() != 0)
    return emitOpError()
           << "requires weight_hmask_byte_offset == 0 (the 32-byte high-bit "
              "plane hmask leads block_q3_K) for the ggml Q3_K x Q8_K "
              "super-block integer partial route";
  if (getWeightQsByteOffset() != 32)
    return emitOpError()
           << "requires weight_qs_byte_offset == 32 (the 64 packed 2-bit-weight "
              "qs bytes follow hmask[32]) for the ggml Q3_K x Q8_K super-block "
              "integer partial route";
  if (getWeightScalesByteOffset() != 96)
    return emitOpError()
           << "requires weight_scales_byte_offset == 96 (the 12 packed "
              "6-bit-signed-scale bytes follow hmask[32]+qs[64]) for the ggml "
              "Q3_K x Q8_K super-block integer partial route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml Q3_K x Q8_K super-block integer partial route";

  // The OPTIONAL loop-form `block_index` operand adds a 6th operand (the
  // per-super-block induction variable). Absent = the standalone 5-operand
  // single-super-block form; present = the loop form. block_index is ODS-typed
  // Index, so no extra type check is needed here.
  unsigned expectedOperands = getBlockIndex() ? 6 : 5;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one aux32 output pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, an OPTIONAL `block_index` "
              "induction operand, and one i32 LMUL m1 result";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q3_K byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  // Loop form (block_index present): the int32_t aux32[8] scratch is a
  // function-scoped variable the super-block loop emitter DECLARES itself, so the
  // output slot is vestigial -- the front door wires it to the weight ABI base to
  // keep the exported ggml C signature the exact 4-role n/s/vx/vy list. Only
  // require its binding there; the standalone form pins the exact 'int32_t *'.
  if (!outputBinding)
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value";
  if (!getBlockIndex() && outputBinding.getCType() != "int32_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'int32_t *' (the per-super-block aux32[8] integer-state "
              "destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q3_K x Q8_K super-block integer partial "
              "route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q3_K x Q8_K super-block integer partial";

  return mlir::success();
}



mlir::LogicalResult Q4KNibbleUnpackOp::verify() {
  mlir::Operation *op = getOperation();

  // Track B q4_K BRICK 1: the op carries ONLY its bounded mirror attrs (I4) --
  // the operation kind and the super-block-format facts the Region-A unpack
  // needs (qk, sub_block, the weight block stride, the qs byte offset). NO scale
  // model (Region A has no scale -- the 6-bit scale/min bit-dance is a deferred
  // brick). A forbidden local element_count/SEW/LMUL/policy attr or an
  // unexpected name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "sub_block" ||
           name == "weight_block_stride" || name == "weight_qs_byte_offset" ||
           name == "weight_qh_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_nibble_unpack keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded nibble-unpack attributes 'kind', "
                "'qk', 'sub_block', 'weight_block_stride', "
                "'weight_qs_byte_offset', and the OPTIONAL q5_K "
                "'weight_qh_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "q4_k_nibble_unpack")
    return emitOpError()
           << "currently supports only kind \"q4_k_nibble_unpack\" for the "
              "bounded q4_K/q5_K Region-A plain 4-bit nibble unpack typed "
              "surface";
  // ggml's externally-defined super-block formats (ggml-common.h): QK_K == 256,
  // 8 sub-blocks of 32 elements. The BRICK is format-parameterized over the
  // bounded (stride, qs_off, qh?) set of the two plain-nibble K-quants it serves,
  // fail-closed on any other tuple (I7):
  //   block_q4_K: stride 144, qs@16 (d@0|dmin@2|scales@4|qs@16),  NO qh plane.
  //   block_q5_K: stride 176, qs@48 (d@0|dmin@2|scales@4|qh@16|qs@48), qh@16.
  // The stride and qs offset are CORRELATED (they select the same format), so the
  // pair is checked as ONE bounded key -- a mixed 144/48 or 176/16 tuple is
  // rejected. This lifts the brick from a q4_K-hardcoded primitive to a
  // format-keyed one (the campaign point), while keeping q4_K 144/16 legal
  // (zero regression).
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the q4_K/q5_K "
                            "Region-A nibble unpack route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "q4_K/q5_K Region-A nibble unpack route";
  int64_t stride = getWeightBlockStride();
  int64_t qsOff = getWeightQsByteOffset();
  bool isQ4KFormat = (stride == 144 && qsOff == 16);
  bool isQ5KFormat = (stride == 176 && qsOff == 48);
  if (!isQ4KFormat && !isQ5KFormat)
    return emitOpError()
           << "requires the (weight_block_stride, weight_qs_byte_offset) pair to "
              "be one of the bounded plain-nibble K-quant formats {(144, 16) "
              "block_q4_K, (176, 48) block_q5_K} for the q4_K/q5_K Region-A "
              "nibble unpack route; got ("
           << stride << ", " << qsOff << ")";
  // The optional qh plane is format-keyed to q5_K: present <=> block_q5_K (stride
  // 176) at qh@16; a qh attr on the q4_K format, an absent qh on the q5_K format,
  // or a wrong qh offset is fail-closed rejected (the 5th-bit inject is exactly
  // the q5_K increment).
  if (getWeightQhByteOffset().has_value()) {
    if (!isQ5KFormat)
      return emitOpError()
             << "must not carry weight_qh_byte_offset on the block_q4_K format "
                "(the qh 5th-bit plane is the q5_K-only increment)";
    if (*getWeightQhByteOffset() != 16)
      return emitOpError()
             << "requires weight_qh_byte_offset == 16 (qh follows d+dmin+"
                "scales[12], before qs@48) for the block_q5_K Region-A nibble "
                "unpack route; got "
             << *getWeightQhByteOffset();
  } else if (isQ5KFormat) {
    return emitOpError()
           << "requires weight_qh_byte_offset (== 16) on the block_q5_K format "
              "(stride 176): the q5_K nibble unpack MUST inject the qh 5th bit";
  }

  // M-FLAT q4_K milestone-2: the OPTIONAL block_index operand toggles the
  // per-super-block-source loop form. Present => the super-block base lives at
  // `weight_base + block_index*weight_block_stride`; absent => the unchanged
  // single-super-block ABI-base form. The block_index is index-typed (ODS) and
  // carries no extra brick attr (the stride the loop op carries).
  bool hasBlockIndex = static_cast<bool>(getBlockIndex());
  unsigned expectedOperands = hasBlockIndex ? 3 : 2;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer runtime ABI operand, one "
              "!weft_rvv.vl operand, one optional block_index induction operand, "
              "and one i32 LMUL m1 result";

  // The weight base operand is a runtime ABI value addressing the AoS block_q4_K
  // byte array as const uint8_t * (the same binding the monolithic
  // weft_rvv.q4_k_q8_k_aux_partial weight base uses).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_K byte array)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> (the side-effect-only completion token) for the q4_K/q5_K "
              "Region-A nibble unpack route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the q4_K/q5_K Region-A nibble unpack";

  return mlir::success();
}

mlir::LogicalResult Q4KScaleMinBitDanceOp::verify() {
  mlir::Operation *op = getOperation();

  // Track B q4_K BRICK 2: the op carries ONLY its bounded mirror attrs (I4) --
  // the operation kind and the super-block-format facts the Region-B 6-bit
  // scale/min bit-dance needs (qk, sub_block, the weight block stride, the scales
  // byte offset). NO scale model (Region B HAS no scale -- it DECODES the 6-bit
  // scales/mins; the per-sub-block dot that applies them is a deferred brick). A
  // forbidden local element_count/SEW/LMUL/policy attr or an unexpected name is
  // rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "sub_block" ||
           name == "weight_block_stride" || name == "weight_scales_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_scale_min_bit_dance keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded scale-min-bit-dance attributes 'kind', "
                "'qk', 'sub_block', 'weight_block_stride', and "
                "'weight_scales_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "q4_k_scale_min_bit_dance")
    return emitOpError()
           << "currently supports only kind \"q4_k_scale_min_bit_dance\" for the "
              "bounded q4_K/q5_K Region-B 6-bit scale/min bit-dance typed "
              "surface";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 8 sub-blocks of 32 elements, block_q4_K stride 144 (d@0|dmin@2|scales@4|
  // qs@16). Pin them so a malformed typed body cannot lower under the Region-B
  // bit-dance emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the q4_K/q5_K "
                            "Region-B scale/min bit-dance route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "q4_K/q5_K Region-B scale/min bit-dance route";
  // Format-keyed to the bounded plain-nibble K-quant strides {144 block_q4_K, 176
  // block_q5_K}; the scales offset (4) is identical for both (Region B decodes the
  // SAME 12 packed scale/min bytes after d+dmin regardless of the qh/qs tail), so
  // only the stride is format-selected here. Any other stride is fail-closed (I7).
  if (getWeightBlockStride() != 144 && getWeightBlockStride() != 176)
    return emitOpError()
           << "requires weight_block_stride in {144 (block_q4_K), 176 "
              "(block_q5_K)} for the q4_K/q5_K Region-B scale/min bit-dance "
              "route; got "
           << getWeightBlockStride();
  if (getWeightScalesByteOffset() != 4)
    return emitOpError()
           << "requires weight_scales_byte_offset == 4 (scales follow d+dmin) "
              "for the q4_K/q5_K Region-B scale/min bit-dance route";

  // M-FLAT q4_K milestone-2: OPTIONAL block_index toggles the per-super-block
  // loop form (see Region-A). Present => scale words at `weight_base +
  // block_index*weight_block_stride + scales_off`; absent => single-super-block.
  bool hasBlockIndex = static_cast<bool>(getBlockIndex());
  unsigned expectedOperands = hasBlockIndex ? 3 : 2;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer runtime ABI operand, one "
              "!weft_rvv.vl operand, one optional block_index induction operand, "
              "and one i32 LMUL m1 result";

  // The weight base operand is a runtime ABI value addressing the AoS block_q4_K
  // byte array as const uint8_t * (the same binding the monolithic
  // weft_rvv.q4_k_q8_k_aux_partial weight base uses; the bit-dance casts it to
  // const uint32_t * at the scales offset).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_K byte array)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> (the side-effect-only completion token) for the q4_K/q5_K "
              "Region-B scale/min bit-dance route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the q4_K/q5_K Region-B scale/min bit-dance";

  return mlir::success();
}

mlir::LogicalResult Q4KScaledDotOp::verify() {
  mlir::Operation *op = getOperation();

  // Track B q4_K BRICK 3: the op carries ONLY its bounded mirror attrs (I4) --
  // the operation kind, the super-block-format facts the Region-C scaled dot
  // needs (qk, sub_block, the weight block stride), and the OPTIONAL
  // integer_core_lmul resource/scheduling anchor (the per-sub-block integer-MAC
  // widening-chain base LMUL). NO scale model (Region C HAS no scale model -- it
  // APPLIES the BRICK 2 decoded 6-bit scales fused into the vwmacc). A forbidden
  // local element_count/SEW/LMUL/policy attr or an unexpected name is rejected
  // fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "sub_block" ||
           name == "weight_block_stride" || name == "integer_core_lmul" ||
           name == "activation_quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_scaled_dot keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded scaled-dot attributes 'kind', 'qk', "
                "'sub_block', 'weight_block_stride', 'integer_core_lmul', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  // The optional integer_core_lmul anchors the per-sub-block integer-MAC
  // widening chain i8 -> i16 -> i32. The legal deployment domain is the
  // bounded resource set {mf2, m1, m2}: m2 is the ceiling because a wider base
  // would require an illegal i32m16 product and span more than one 32-element
  // sub-block under a scalar scale. Retired experimental strategy tokens are
  // ordinary unknown values and follow this same fail-closed diagnostic.
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1" && coreLmul != "m2")
      return emitOpError()
             << "requires integer_core_lmul in {\"mf2\", \"m1\", \"m2\"} "
                "(the bounded base LMUL of the i8 -> i16 -> i32 integer-MAC "
                "chain; \"m2\" is the ceiling at one sub-block == 32 elements "
                "per scalar scale) for the q4_K/q5_K Region-C scaled-dot route; "
                "got \""
             << coreLmul << "\"";
  }

  if (getKind() != "q4_k_scaled_dot")
    return emitOpError()
           << "currently supports only kind \"q4_k_scaled_dot\" for the bounded "
              "q4_K/q5_K Region-C per-sub-block uint6-scaled i32 dot + integer "
              "fold-back typed surface";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, block_q4_K stride 144 (d@0|dmin@2|scales@4|qs@16).
  // Pin them so a malformed typed body cannot lower under the Region-C emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the q4_K/q5_K "
                            "Region-C scaled-dot route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block scale boundary) "
              "for the q4_K/q5_K Region-C scaled-dot route";
  // Format-keyed to the bounded plain-nibble K-quant strides {144 block_q4_K, 176
  // block_q5_K}; Region C reads the BRICK 1 unpacked aux8 scratch (already lifted
  // to q5 in [0,31] by the qh inject) + the q8 activation, so its per-sub-block
  // MAC is identical across the two formats and only the stride is format-selected
  // (the weight base advances by stride*ib). Any other stride is fail-closed (I7).
  if (getWeightBlockStride() != 144 && getWeightBlockStride() != 176)
    return emitOpError()
           << "requires weight_block_stride in {144 (block_q4_K), 176 "
              "(block_q5_K)} for the q4_K/q5_K Region-C scaled-dot route; got "
           << getWeightBlockStride();

  // M-FLAT q4_K milestone-2: OPTIONAL block_index toggles the per-super-block
  // loop form. Present => the q8 strip lives at `q8_base +
  // block_index*activation_block_stride + activation_quant_byte_offset` (the
  // stride the loop op carries); absent => single-super-block (q8_base is the q8
  // data pointer directly). The activation_quant_byte_offset is a loop-form fact:
  // it is fail-closed rejected without block_index (I7).
  bool hasBlockIndex = static_cast<bool>(getBlockIndex());
  unsigned expectedOperands = hasBlockIndex ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires three runtime ABI base pointer operands (aux8 / scales / "
              "q8), one !weft_rvv.vl operand, one optional block_index induction "
              "operand, and one i32 LMUL m1 result";
  if (!hasBlockIndex && getActivationQuantByteOffset())
    return emitOpError()
           << "must not set activation_quant_byte_offset without block_index "
              "(the single-super-block form passes the q8 data pointer directly "
              "at offset 0)";

  // The three base operands are runtime ABI values: the BRICK 1 unpacked aux8
  // scratch (const int8_t *), the BRICK 2 decoded scales (const uint8_t *), and
  // the q8_K activation data (const uint8_t * -- the same binding the monolithic
  // q4_K core's activation base uses; the dot casts it to const int8_t *).
  RuntimeABIValueOp aux8Binding =
      getAux8Base().getDefiningOp<RuntimeABIValueOp>();
  // In the loop form (block_index present -- nested in a
  // typed_super_block_block_dot_loop_body) the int8_t aux8[256] scratch is a
  // function-scoped variable the super-block loop emitter DECLARES itself, and it
  // never reads this operand slot; the slot is vestigial (the front door wires it
  // to the weight base to keep the exported ggml C signature the exact 4-role
  // list), so only its binding-to-a-runtime-ABI-value is required. The standalone
  // single-super-block form still pins the exact 'const int8_t *' scratch type.
  if (!aux8Binding)
    return emitOpError()
           << "requires the aux8 base operand to bind a runtime ABI value";
  if (!hasBlockIndex && aux8Binding.getCType() != "const int8_t *")
    return emitOpError()
           << "requires the aux8 base operand to bind a runtime ABI value of C "
              "type 'const int8_t *' (the BRICK 1 unpacked aux8[256] scratch)";
  RuntimeABIValueOp scalesBinding =
      getScalesBase().getDefiningOp<RuntimeABIValueOp>();
  if (!scalesBinding || scalesBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the scales base operand to bind a runtime ABI value of C "
              "type 'const uint8_t *' (the BRICK 2 decoded 6-bit scales)";
  RuntimeABIValueOp q8Binding = getQ8Base().getDefiningOp<RuntimeABIValueOp>();
  if (!q8Binding || q8Binding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the q8 base operand to bind a runtime ABI value of C "
              "type 'const uint8_t *' (the q8_K activation data)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> (the side-effect-only completion token) for the q4_K/q5_K "
              "Region-C scaled-dot route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the q4_K/q5_K Region-C scaled dot";

  return mlir::success();
}

mlir::LogicalResult Q4KMinTermOp::verify() {
  mlir::Operation *op = getOperation();

  // Track B q4_K BRICK 4: the op carries ONLY its bounded mirror attrs (I4) --
  // the operation kind and the super-block-format facts the MIN term needs (qk,
  // sub_block, num_sub_blocks, the q8_K bsums byte offset, and the weight dmin
  // byte offset). NO scale model and NO LMUL/resource knob (the MIN term is a
  // SCALAR integer reduction + a single fp contraction -- there is no widening
  // axis). A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "sub_block" ||
           name == "num_sub_blocks" || name == "bsums_byte_offset" ||
           name == "weight_dmin_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_min_term keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded min-term attributes 'kind', 'qk', "
                "'sub_block', 'num_sub_blocks', 'bsums_byte_offset', and "
                "'weight_dmin_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "q4_k_min_term")
    return emitOpError()
           << "currently supports only kind \"q4_k_min_term\" for the bounded "
              "q4_K/q5_K MIN-term (sumf -= dmin * sum(mins * bsums)) typed "
              "surface";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, 16 i16 bsums (one per 16 elements), the q8_K
  // bsums at byte offset 260, and the weight dmin (fp16) at byte offset 2. Pin
  // them so a malformed typed body cannot lower under the MIN-term emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the q4_K/q5_K "
                            "MIN-term route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block scale boundary) "
              "for the q4_K/q5_K MIN-term route";
  if (getNumSubBlocks() != 8)
    return emitOpError()
           << "requires num_sub_blocks == 8 (QK_K / 32) for the q4_K/q5_K "
              "MIN-term route";
  if (getBsumsByteOffset() != 260)
    return emitOpError()
           << "requires bsums_byte_offset == 260 (the q8_K block bsums offset) "
              "for the q4_K/q5_K MIN-term route";
  if (getWeightDminByteOffset() != 2)
    return emitOpError()
           << "requires weight_dmin_byte_offset == 2 (the block_q4_K/q5_K dmin "
              "fp16 offset) for the q4_K/q5_K MIN-term route";

  // M-FLAT q4_K milestone-2: OPTIONAL block_index toggles the per-super-block
  // loop form. Present => the fp16 dmin / int16 bsums / fp32 activation d live at
  // `weight_base|activation_base + block_index*stride (the strides the loop op
  // carries)`; absent => single-super-block.
  bool hasBlockIndex = static_cast<bool>(getBlockIndex());
  unsigned expectedOperands = hasBlockIndex ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires three runtime ABI base pointer operands (weight / "
              "scales / activation), one !weft_rvv.vl operand, one optional "
              "block_index induction operand, and one i32 LMUL m1 result";

  // The three base operands are runtime ABI values: the q4_K/q5_K weight block
  // (const uint8_t *, read at +2 for the fp16 dmin), the BRICK 2 decoded scales
  // (const uint8_t *, whose bytes [8..15] are the 8 decoded uint6 mins), and the
  // q8_K activation data (const uint8_t *, read at +260 for the int16 bsums and
  // at +0 for the fp32 activation scale).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the q4_K/q5_K weight block; the fp16 "
              "dmin lives at byte offset 2)";
  RuntimeABIValueOp scalesBinding =
      getScalesBase().getDefiningOp<RuntimeABIValueOp>();
  if (!scalesBinding || scalesBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the scales base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the BRICK 2 decoded scales; the 8 mins "
              "live at bytes [8..15])";
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI value "
              "of C type 'const uint8_t *' (the q8_K activation data; the int16 "
              "bsums live at byte offset 260)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> (the side-effect-only completion token) for the q4_K/q5_K "
              "MIN-term route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the q4_K/q5_K MIN term";

  return mlir::success();
}

mlir::LogicalResult Q4KSumsFoldScaleDOp::verify() {
  mlir::Operation *op = getOperation();

  // Track B q4_K BRICK 6: the op carries ONLY its bounded mirror attrs (I4) --
  // the operation kind and the super-block-format facts the positive fold needs
  // (qk, sub_block, num_sub_blocks, and the weight d fp16 byte offset). NO scale
  // model and NO LMUL/resource knob (the canonical-8 fp fold is fixed at 8 lanes
  // f32m2 -- the integer-core widening axis lives on the upstream BRICK 3 scaled
  // dot). A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "sub_block" ||
           name == "num_sub_blocks" || name == "weight_d_byte_offset" ||
           // A-line g-axis debake (路 B): the canonical fp32 sums lane count
           // descriptor fact (8), read fail-closed by the EmitC fold.
           name == "num_lanes";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_sums_fold_scale_d keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded sums-fold attributes 'kind', 'qk', "
                "'sub_block', 'num_sub_blocks', and 'weight_d_byte_offset'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "q4_k_sums_fold_scale_d")
    return emitOpError()
           << "currently supports only kind \"q4_k_sums_fold_scale_d\" for the "
              "bounded q4_K/q5_K positive-fold (sums += fp16(x.d) * y.d * "
              "(float)aux32) typed surface";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, and the weight d (fp16) at byte offset 0. Pin them
  // so a malformed typed body cannot lower under the positive-fold emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the q4_K/q5_K "
                            "positive-fold route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block scale boundary) "
              "for the q4_K/q5_K positive-fold route";
  if (getNumSubBlocks() != 8)
    return emitOpError()
           << "requires num_sub_blocks == 8 (QK_K / 32) for the q4_K/q5_K "
              "positive-fold route";
  // The fp16 weight super-block scale d byte offset the positive fold reads: 0
  // for q4_K/q5_K (block_q4_K/q5_K d @0), 208 for q6_K (block_q6_K d @208), 108
  // for q3_K (block_q3_K d @108 -- BOTH no-min single-accumulator routes REUSE this
  // same positive fold, differing only in the d offset). Any other offset is
  // rejected fail-closed (I7).
  if (getWeightDByteOffset() != 0 && getWeightDByteOffset() != 208 &&
      getWeightDByteOffset() != 108)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (block_q4_K/q5_K d fp16 @0), "
              "208 (block_q6_K d fp16 @208), or 108 (block_q3_K d fp16 @108) -- "
              "the q6_K/q3_K no-min positive-fold reuse -- for the shared "
              "positive-fold route";

  // M-FLAT q4_K milestone-2: OPTIONAL block_index toggles the per-super-block
  // loop form. Present => the fp16 weight scale d / fp32 activation d live at
  // `weight_base|activation_base + block_index*stride (the strides the loop op
  // carries)`; absent => single-super-block.
  bool hasBlockIndex = static_cast<bool>(getBlockIndex());
  unsigned expectedOperands = hasBlockIndex ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires three runtime ABI base pointer operands (weight / aux32 "
              "/ activation), one !weft_rvv.vl operand, one optional block_index "
              "induction operand, and one i32 LMUL m1 result";

  // The three base operands are runtime ABI values: the q4_K/q5_K weight block
  // (const uint8_t *, read at +0 for the fp16 d), the BRICK 3 canonical-8 aux32
  // integer dot result (const int32_t *, vle32-loaded into a vint32m2_t), and the
  // q8_K activation data (const uint8_t *, read at +0 for the fp32 activation
  // scale y.d).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the q4_K/q5_K weight block; the fp16 d "
              "lives at byte offset 0)";
  RuntimeABIValueOp aux32Binding =
      getAux32Base().getDefiningOp<RuntimeABIValueOp>();
  // In the loop form (block_index present) the int32_t aux32[8] scratch is a
  // function-scoped variable the super-block loop emitter DECLARES itself, and it
  // never reads this operand slot; the slot is vestigial (the front door wires it
  // to the weight base to keep the exported ggml C signature the exact 4-role
  // list), so only its binding-to-a-runtime-ABI-value is required. The standalone
  // single-super-block form still pins the exact 'const int32_t *' scratch type.
  if (!aux32Binding)
    return emitOpError()
           << "requires the aux32 base operand to bind a runtime ABI value";
  if (!hasBlockIndex && aux32Binding.getCType() != "const int32_t *")
    return emitOpError()
           << "requires the aux32 base operand to bind a runtime ABI value of C "
              "type 'const int32_t *' (the BRICK 3 canonical-8 integer dot "
              "result, vle32-loaded into a vint32m2_t)";
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI value "
              "of C type 'const uint8_t *' (the q8_K activation data; the fp32 "
              "scale y.d lives at byte offset 0)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> (the side-effect-only completion token) for the q4_K/q5_K "
              "positive-fold route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the q4_K/q5_K positive fold";

  return mlir::success();
}

mlir::LogicalResult Q4KHorizontalFoldOp::verify() {
  mlir::Operation *op = getOperation();

  // Track B q4_K BRICK 7: the op carries ONLY its bounded mirror attrs (I4) -- the
  // operation kind and the super-block-format facts the post-loop horizontal fold
  // needs (qk, sub_block, num_sub_blocks, and the canonical fp32 lane count). NO
  // scale model and NO LMUL/resource knob (the horizontal collapse is fixed at 8
  // lanes f32m2 and a fixed sequential ascending sum -- the integer-core widening
  // axis lives on the upstream BRICK 3 scaled dot). A forbidden local
  // element_count/SEW/LMUL/policy attr or an unexpected name is rejected
  // fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "sub_block" ||
           name == "num_sub_blocks" || name == "num_lanes";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_horizontal_fold keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded horizontal-fold attributes 'kind', "
                "'qk', 'sub_block', 'num_sub_blocks', and 'num_lanes'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "q4_k_horizontal_fold")
    return emitOpError()
           << "currently supports only kind \"q4_k_horizontal_fold\" for the "
              "bounded q4_K/q5_K post-loop horizontal-fold (sumf += sums8[0..7], "
              "sequential) typed surface";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, and the canonical 8-lane fp32 accumulator. Pin them
  // so a malformed typed body cannot lower under the horizontal-fold emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the q4_K/q5_K "
                            "horizontal-fold route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block scale boundary) "
              "for the q4_K/q5_K horizontal-fold route";
  if (getNumSubBlocks() != 8)
    return emitOpError()
           << "requires num_sub_blocks == 8 (QK_K / 32) for the q4_K/q5_K "
              "horizontal-fold route";
  if (getNumLanes() != 8)
    return emitOpError()
           << "requires num_lanes == 8 (the canonical fp32 sums lane count) for "
              "the q4_K/q5_K horizontal-fold route";

  if (op->getNumOperands() != 2 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one runtime ABI base pointer operand (the 8-lane fp32 "
              "sums source), one !weft_rvv.vl operand, and one i32 LMUL m1 result";

  // The single base operand is a runtime ABI value: the 8-lane fp32 sums source
  // (const float *, vle32-loaded into a vfloat32m2_t the horizontal fold collapses).
  RuntimeABIValueOp sumsBinding =
      getSumsBase().getDefiningOp<RuntimeABIValueOp>();
  if (!sumsBinding || sumsBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the sums base operand to bind a runtime ABI value of C "
              "type 'const float *' (the 8-lane fp32 sums accumulator source, "
              "vle32-loaded into a vfloat32m2_t)";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> (the side-effect-only completion token) for the q4_K/q5_K "
              "horizontal-fold route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the q4_K/q5_K horizontal fold";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotQ4KQ8KAux32Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // per-sub-block uint6 scale model, and the super-block-format structural facts.
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_scales_byte_offset" ||
           name == "weight_qs_byte_offset" ||
           name == "activation_quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q4_k_q8_k_aux_partial keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded super-block dot-product attributes "
                "'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_scales_byte_offset', 'weight_qs_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q4_k_q8_k_aux_partial")
    return emitOpError()
           << "currently supports only kind \"ggml_q4_k_q8_k_aux_partial\" "
              "for the bounded ggml Q4_K x Q8_K super-block integer partial "
              "typed surface";
  if (getScaleModel() != "per-sub-block-uint6-scale-i32-domain")
    return emitOpError()
           << "requires scale_model \"per-sub-block-uint6-scale-i32-domain\" "
              "for the ggml Q4_K x Q8_K super-block integer partial route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 8 sub-blocks of 32 elements, block_q4_K stride 144 (d@0|dmin@2|scales@4|
  // qs@16), block_q8_K stride 292 (d@0|qs@4|bsums@260). Pin them so a malformed
  // typed body cannot lower under the super-block partial emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml Q4_K x "
                            "Q8_K super-block integer partial route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block scale boundary) "
              "for the ggml Q4_K x Q8_K super-block integer partial route";
  if (getWeightBlockStride() != 144)
    return emitOpError()
           << "requires weight_block_stride == 144 (sizeof block_q4_K) for the "
              "ggml Q4_K x Q8_K super-block integer partial route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml Q4_K x Q8_K super-block integer partial route";
  if (getWeightScalesByteOffset() != 4)
    return emitOpError()
           << "requires weight_scales_byte_offset == 4 (the 12 packed scale/min "
              "bytes follow d+dmin) for the ggml Q4_K x Q8_K super-block integer "
              "partial route";
  if (getWeightQsByteOffset() != 16)
    return emitOpError()
           << "requires weight_qs_byte_offset == 16 (qs follow d+dmin+scales[12]) "
              "for the ggml Q4_K x Q8_K super-block integer partial route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml Q4_K x Q8_K super-block integer partial route";

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one aux32 output pointer, one scale/min output pointer, one "
              "runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, and one i32 LMUL m1 result";

  // The four buffer operands and the element count are runtime ABI values; the
  // weight/activation bases address the AoS byte arrays as const uint8_t *, the
  // aux32 output is an int32_t * (the 8-lane aux32 integer-state destination --
  // NOT the fp32 *s of the K4b fold), the scale/min output is a uint8_t * (the
  // 16 decoded scale/min bytes per super-block), and the element count carries n.
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp aux32Binding =
      getAux32Output().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp scaleMinBinding =
      getScaleminOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_K byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!aux32Binding || aux32Binding.getCType() != "int32_t *")
    return emitOpError()
           << "requires the aux32 output operand to bind a runtime ABI value "
              "of C type 'int32_t *' (the per-super-block aux32[8] integer-state "
              "destination)";
  if (!scaleMinBinding || scaleMinBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the scale/min output operand to bind a runtime ABI "
              "value of C type 'uint8_t *' (the per-super-block 16 decoded "
              "scale/min bytes)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<i32, "
              "\"m1\"> for the ggml Q4_K x Q8_K super-block integer partial "
              "route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q4_K x Q8_K super-block integer partial";

  return mlir::success();
}







mlir::LogicalResult GgmlBlockDotQ2KQ8KIntegerCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // uint4-nibble scale+min integer-core scale model, and the q2_K
  // super-block-format structural facts the integer core reads (the 16 packed
  // 4-bit-scale/4-bit-min `scales` @0, the 64 packed 2-bit-weight qs @16, the
  // q8_K qs @4, and the int16 q8_K per-sub-block sums bsums @260). The fp16
  // weight d @80 / dmin @82 and the fp32 activation d @0 are the milestone-2
  // fold's, NOT the integer core's. Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected
  // fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_scales_byte_offset" ||
           name == "weight_qs_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "activation_bsums_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.q2_k_q8_k_integer_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded super-block integer-core attributes "
                "'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_scales_byte_offset', 'weight_qs_byte_offset', "
                "'activation_quant_byte_offset', and "
                "'activation_bsums_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_q2_k_q8_k_integer_core")
    return emitOpError()
           << "currently supports only kind \"ggml_q2_k_q8_k_integer_core\" "
              "for the bounded ggml Q2_K x Q8_K super-block scalar integer-core "
              "typed surface";
  if (getScaleModel() != "per-sub-block-uint4-scale-i32-domain-min")
    return emitOpError()
           << "requires scale_model "
              "\"per-sub-block-uint4-scale-i32-domain-min\" for the ggml Q2_K x "
              "Q8_K super-block scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 16 sub-blocks of 16 elements, block_q2_K stride 84 (scales@0|qs@16|d@80|
  // dmin@82), block_q8_K stride 292 (d@0|qs@4|bsums@260). The integer core reads
  // scales (the 4-bit scale/min nibbles), qs (2-bit weights), the q8_K quants,
  // and bsums (the min integer sum); pin them so a malformed typed body cannot
  // lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml Q2_K x "
                            "Q8_K super-block scalar integer-core route";
  if (getSubBlock() != 16)
    return emitOpError()
           << "requires sub_block == 16 (16-element sub-block scale boundary) "
              "for the ggml Q2_K x Q8_K super-block scalar integer-core route";
  if (getWeightBlockStride() != 84)
    return emitOpError()
           << "requires weight_block_stride == 84 (sizeof block_q2_K) for the "
              "ggml Q2_K x Q8_K super-block scalar integer-core route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml Q2_K x Q8_K super-block scalar integer-core route";
  if (getWeightScalesByteOffset() != 0)
    return emitOpError()
           << "requires weight_scales_byte_offset == 0 (the 16 packed "
              "4-bit-scale/4-bit-min bytes lead block_q2_K) for the ggml Q2_K x "
              "Q8_K super-block scalar integer-core route";
  if (getWeightQsByteOffset() != 16)
    return emitOpError()
           << "requires weight_qs_byte_offset == 16 (the 64 packed 2-bit-weight "
              "qs bytes follow scales[16]) for the ggml Q2_K x Q8_K super-block "
              "scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml Q2_K x Q8_K super-block scalar integer-core route";
  if (getActivationBsumsByteOffset() != 260)
    return emitOpError()
           << "requires activation_bsums_byte_offset == 260 (the int16 "
              "per-sub-block sums bsums follow d+qs[256]) for the ggml Q2_K x "
              "Q8_K super-block scalar integer-core route";

  // M-FLAT q2_K milestone-1: the OPTIONAL loop-form `block_index` operand adds a
  // 5th operand (the per-super-block induction variable). Absent = the standalone
  // 4-operand single-super-block form; present = the loop form. block_index is
  // ODS-typed Index, so no extra type check is needed here. The op produces TWO
  // scalar i32 results (isum, summs) -- NO output pointer (the scalar states are
  // SSA results, not an aux32 memory state).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 2)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and two "
              "scalar i32 results (isum, summs)";

  // The weight/activation bases address the AoS byte arrays as const uint8_t *,
  // and the element count carries n. q2_K's integer core has NO output pointer
  // (isum/summs are scalar SSA results, not an aux32 memory state).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q2_K byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // The two scalar integer-core results are ggml's `int isum` (the uint4-scaled
  // positive dot) and `int summs` (the min integer sum), both scalar i32.
  if (!getIsum().getType().isInteger(32))
    return emitOpError()
           << "requires the first result (isum, the uint4-nibble-scaled positive "
              "integer dot) to be scalar i32";
  if (!getSumms().getType().isInteger(32))
    return emitOpError()
           << "requires the second result (summs, the q2_K min integer sum) to "
              "be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml Q2_K x Q8_K super-block scalar integer "
              "core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ1SQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // qh-scaled ternary-grid-codebook delta-bsum integer-core scale model, and the
  // iq1_s super-block-format structural facts the integer core reads (the 32
  // uint8 grid-index bytes qs @2, the uint16 qh[8] plane @34 carrying the
  // grid-high-3-bit fields + the 3-bit scale @12..14 + the delta sign @15, the
  // q8_K qs @4, and the int16 q8_K per-sub-block sums bsums @260). The fp16
  // weight d @0 and the fp32 activation d @0 are the milestone-2 fold's, NOT the
  // integer core's. iq1_s carries NO scales[] array (the scale lives in qh bits
  // 12..14) and NO sign plane (the ternary grid is itself signed). Anything else
  // -- a forbidden local element_count/SEW/LMUL/policy attr, or an unexpected
  // name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_qs_byte_offset" || name == "weight_qh_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "activation_bsums_byte_offset" ||
           // A-line g-axis debake (路 B): the iq1_s grid group count descriptor.
           name == "groups_per_sub";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq1_s_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded TERNARY-grid super-block "
                "integer-core attributes 'kind', 'scale_model', 'qk', "
                "'sub_block', 'weight_block_stride', 'activation_block_stride', "
                "'weight_qs_byte_offset', 'weight_qh_byte_offset', "
                "'activation_quant_byte_offset', and "
                "'activation_bsums_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq1_s_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq1_s_q8_k_grid_core\" "
              "for the bounded ggml IQ1_S x Q8_K super-block TERNARY-grid scalar "
              "integer-core typed surface";
  if (getScaleModel() !=
      "per-sub-block-qh-scale-ternary-grid-codebook-delta-bsum-int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-sub-block-qh-scale-ternary-grid-codebook-delta-bsum-int-"
              "domain\" for the ggml IQ1_S x Q8_K super-block TERNARY-grid "
              "scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 8 sub-blocks of 32 elements, block_iq1_s stride 50 (d@0|qs[32]@2|qh[8]@34),
  // block_q8_K stride 292 (d@0|qs@4|bsums@260). The integer core reads qs (the
  // grid-index bytes), qh (the grid-high bits + scale + delta sign), the q8_K
  // quants, and bsums (the delta integer sum); pin them so a malformed typed body
  // cannot lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ1_S x "
                            "Q8_K super-block TERNARY-grid scalar integer-core "
                            "route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ1_S x Q8_K super-block TERNARY-grid scalar integer-core "
              "route";
  if (getWeightBlockStride() != 50)
    return emitOpError()
           << "requires weight_block_stride == 50 (sizeof block_iq1_s) for the "
              "ggml IQ1_S x Q8_K super-block TERNARY-grid scalar integer-core "
              "route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ1_S x Q8_K super-block TERNARY-grid scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 2)
    return emitOpError()
           << "requires weight_qs_byte_offset == 2 (the 32 uint8 grid-index qs "
              "bytes follow the fp16 d) for the ggml IQ1_S x Q8_K super-block "
              "TERNARY-grid scalar integer-core route";
  if (getWeightQhByteOffset() != 34)
    return emitOpError()
           << "requires weight_qh_byte_offset == 34 (the uint16 qh[8] plane "
              "follows the 32-byte qs; it carries the grid-high-3-bit fields, "
              "the 3-bit scale @12..14, and the delta sign @15) for the ggml "
              "IQ1_S x Q8_K super-block TERNARY-grid scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml IQ1_S x Q8_K super-block TERNARY-grid scalar "
              "integer-core route";
  if (getActivationBsumsByteOffset() != 260)
    return emitOpError()
           << "requires activation_bsums_byte_offset == 260 (the int16 "
              "per-sub-block sums bsums follow d+qs[256]; the load-bearing fact "
              "of the delta term) for the ggml IQ1_S x Q8_K super-block "
              "TERNARY-grid scalar integer-core route";

  // M-FLAT iq1_s milestone-1: the OPTIONAL loop-form `block_index` operand adds a
  // 5th operand (the per-super-block induction variable). Absent = the standalone
  // 4-operand single-super-block form; present = the loop form. block_index is
  // ODS-typed Index, so no extra type check is needed here. The op produces TWO
  // scalar i32 results (sumi, sumi1) -- NO output pointer (the scalar states are
  // SSA results, not an aux32 memory state).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 2)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and two "
              "scalar i32 results (sumi, sumi1)";

  // The weight/activation bases address the AoS byte arrays as const uint8_t *,
  // and the element count carries n. iq1_s's integer core has NO output pointer
  // (sumi/sumi1 are scalar SSA results, not an aux32 memory state).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq1_s byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // The two scalar integer-core results are ggml's `int sumi` (the qh-scaled
  // ternary-grid positive dot) and `int sumi1` (the iq1_s delta integer sum),
  // both scalar i32.
  if (!getSumi().getType().isInteger(32))
    return emitOpError()
           << "requires the first result (sumi, the qh-scaled ternary-grid "
              "positive integer dot) to be scalar i32";
  if (!getSumi1().getType().isInteger(32))
    return emitOpError()
           << "requires the second result (sumi1, the iq1_s delta integer sum) "
              "to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ1_S x Q8_K super-block TERNARY-grid "
              "scalar integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ1MQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // packed-iq1m-scale per-half-scale ternary-grid-codebook per-group-delta
  // integer-core scale model, and the iq1_m super-block-format structural facts the
  // integer core reads (the 32 uint8 grid-index bytes qs @0, the 16 uint8 qh[16]
  // plane @32 carrying the grid-high-3-bit fields + the 4 per-group delta signs, the
  // 4 uint16 packed scales[] words @48 carrying the packed fp16 d nibbles + the
  // per-sub-block 3-bit half scales, and the q8_K qs @4). iq1_m has NO fp16 weight d
  // field (the scale is RECONSTRUCTED from scales[]) and reads NO bsums (the four
  // independent group delta signs make the q8 bsums unusable). Anything else -- a
  // forbidden local element_count/SEW/LMUL/policy attr, or an unexpected name -- is
  // rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_qs_byte_offset" || name == "weight_qh_byte_offset" ||
           name == "weight_scales_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           // A-line g-axis debake (路 B): the iq1_m grid group count descriptor.
           name == "groups_per_sub";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq1_m_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded TERNARY-grid super-block "
                "integer-core attributes 'kind', 'scale_model', 'qk', "
                "'sub_block', 'weight_block_stride', 'activation_block_stride', "
                "'weight_qs_byte_offset', 'weight_qh_byte_offset', "
                "'weight_scales_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq1_m_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq1_m_q8_k_grid_core\" "
              "for the bounded ggml IQ1_M x Q8_K super-block TERNARY-grid scalar "
              "integer-core typed surface";
  if (getScaleModel() !=
      "packed-iq1m-scale-per-half-scale-ternary-grid-codebook-per-group-delta-"
      "int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"packed-iq1m-scale-per-half-scale-ternary-grid-codebook-per-"
              "group-delta-int-domain\" for the ggml IQ1_M x Q8_K super-block "
              "TERNARY-grid scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 8 sub-blocks of 32 elements, block_iq1_m stride 56 (qs[32]@0|qh[16]@32|
  // scales[8]@48, NO fp16 d field), block_q8_K stride 292 (d@0|qs@4). The integer
  // core reads qs (the grid-index bytes), qh (the grid-high bits + the 4 delta
  // signs), the packed scales[] words (the packed fp16 d + the half scales), and the
  // q8_K quants; pin them so a malformed typed body cannot lower under the
  // integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ1_M x "
                            "Q8_K super-block TERNARY-grid scalar integer-core "
                            "route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ1_M x Q8_K super-block TERNARY-grid scalar integer-core "
              "route";
  if (getWeightBlockStride() != 56)
    return emitOpError()
           << "requires weight_block_stride == 56 (sizeof block_iq1_m, NO fp16 d "
              "field) for the ggml IQ1_M x Q8_K super-block TERNARY-grid scalar "
              "integer-core route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ1_M x Q8_K super-block TERNARY-grid scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 0)
    return emitOpError()
           << "requires weight_qs_byte_offset == 0 (the 32 uint8 grid-index qs "
              "bytes lead block_iq1_m; there is NO fp16 d field) for the ggml "
              "IQ1_M x Q8_K super-block TERNARY-grid scalar integer-core route";
  if (getWeightQhByteOffset() != 32)
    return emitOpError()
           << "requires weight_qh_byte_offset == 32 (the 16 uint8 qh[16] plane "
              "follows the 32-byte qs; it carries the grid-high-3-bit fields + "
              "the 4 per-group delta signs) for the ggml IQ1_M x Q8_K "
              "super-block TERNARY-grid scalar integer-core route";
  if (getWeightScalesByteOffset() != 48)
    return emitOpError()
           << "requires weight_scales_byte_offset == 48 (the 4 uint16 packed "
              "scales[] words follow qs[32]+qh[16]; they carry the packed fp16 d "
              "nibbles + the per-sub-block 3-bit half scales) for the ggml IQ1_M "
              "x Q8_K super-block TERNARY-grid scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml IQ1_M x Q8_K super-block TERNARY-grid scalar "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. block_index is ODS-typed
  // Index. The op produces TWO scalar i32 results (sumi1, sumi2) -- NO output
  // pointer (the scalar states are SSA results, not an aux32 memory state).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 2)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and two "
              "scalar i32 results (sumi1, sumi2)";

  // The weight/activation bases address the AoS byte arrays as const uint8_t *.
  // iq1_m's integer core has NO output pointer (sumi1/sumi2 are scalar SSA
  // results, not an aux32 memory state).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq1_m byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // The two scalar integer-core results are ggml's `int sumi1` (the qh-index
  // half-scaled ternary-grid grid dot) and `int sumi2` (the iq1_m per-group delta
  // integer sum), both scalar i32.
  if (!getSumi1().getType().isInteger(32))
    return emitOpError()
           << "requires the first result (sumi1, the half-scaled ternary-grid "
              "grid dot) to be scalar i32";
  if (!getSumi2().getType().isInteger(32))
    return emitOpError()
           << "requires the second result (sumi2, the iq1_m per-group delta "
              "integer sum) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ1_M x Q8_K super-block TERNARY-grid "
              "scalar integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ3XXSQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // aux32-scale grid-of-4-codebook ksigns-sign-plane integer-core scale model, and
  // the iq3_xxs super-block-format structural facts the integer core reads (the fp16
  // d @0, the 64 uint8 grid-index bytes qs @2, the 32 aux bytes gas @66, the q8_K
  // fp32 d @0, the q8_K qs @4). The FIXED 256-entry iq3xxs_grid GRID-of-4 codebook and
  // the 128-entry ksigns_iq2xs sign plane are byte-exact constants of the FORMAT
  // (keyed off the brick op identity at emit), NOT carried in the IR. Anything else --
  // a forbidden local element_count/SEW/LMUL/policy attr, or an unexpected name -- is
  // rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_d_byte_offset" || name == "weight_qs_byte_offset" ||
           name == "weight_gas_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           // A-line g-axis debake (路 B): the iq3_xxs grid sub-structure counts.
           name == "num_groups" || name == "indices_per_sub_block" ||
           name == "group_lanes";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq3_xxs_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded GRID-of-4 super-block integer-core "
                "attributes 'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_d_byte_offset', 'weight_qs_byte_offset', "
                "'weight_gas_byte_offset', 'activation_d_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq3_xxs_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq3_xxs_q8_k_grid_core\" "
              "for the bounded ggml IQ3_XXS x Q8_K super-block GRID-of-4 scalar "
              "integer-core typed surface";
  if (getScaleModel() !=
      "per-sub-block-aux32-scale-grid-of-4-codebook-ksigns-sign-plane-int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-sub-block-aux32-scale-grid-of-4-codebook-ksigns-sign-plane-"
              "int-domain\" for the ggml IQ3_XXS x Q8_K super-block GRID-of-4 "
              "scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, block_iq3_xxs stride 98 (d@0|qs[64]@2|gas[32]@66),
  // block_q8_K stride 292 (d@0|qs@4). Pin the facts so a malformed typed body cannot
  // lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ3_XXS x "
                            "Q8_K super-block GRID-of-4 scalar integer-core route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ3_XXS x Q8_K super-block GRID-of-4 scalar integer-core "
              "route";
  if (getWeightBlockStride() != 98)
    return emitOpError()
           << "requires weight_block_stride == 98 (sizeof block_iq3_xxs) for the "
              "ggml IQ3_XXS x Q8_K super-block GRID-of-4 scalar integer-core "
              "route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ3_XXS x Q8_K super-block GRID-of-4 scalar integer-core "
              "route";
  if (getWeightDByteOffset() != 0)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (the fp16 d leads block_iq3_xxs) "
              "for the ggml IQ3_XXS x Q8_K super-block GRID-of-4 scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 2)
    return emitOpError()
           << "requires weight_qs_byte_offset == 2 (the 64 uint8 grid-index qs "
              "bytes follow the fp16 d) for the ggml IQ3_XXS x Q8_K super-block "
              "GRID-of-4 scalar integer-core route";
  if (getWeightGasByteOffset() != 66)
    return emitOpError()
           << "requires weight_gas_byte_offset == 66 (the 32 aux bytes gas follow "
              "d + the 64 grid-index bytes; they carry the per-sub-block aux32 = "
              "4-bit scale + 4 sign selectors) for the ggml IQ3_XXS x Q8_K "
              "super-block GRID-of-4 scalar integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 d leads "
              "block_q8_K) for the ggml IQ3_XXS x Q8_K super-block GRID-of-4 "
              "scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 d) "
              "for the ggml IQ3_XXS x Q8_K super-block GRID-of-4 scalar "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (bsum) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (bsum)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq3_xxs byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getBsum().getType().isInteger(32))
    return emitOpError()
           << "requires the result (bsum, the per-super-block 4-bit-scaled "
              "grid/sign integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ3_XXS x Q8_K super-block GRID-of-4 "
              "scalar integer core";

  return mlir::success();
}



mlir::LogicalResult GgmlBlockDotTQ20Q8KTernaryCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // ternary-2bit-fused-plane single-fp16-scale integer-core scale model, and the
  // super-block-format structural facts the integer core reads (the 64 packed
  // 2-bit-weight qs @0, the fp16 weight scale d @64 -- d is at the END of
  // block_tq2_0, distinct from every sibling -- the fp32 activation scale d @0,
  // qs @4), plus the final resource shape knob integer_core_lmul + semantic
  // minimum_vlen. tq2_0 is
  // TERNARY with NO scales[16], NO per-sub-block scale, NO min term, NO dmin, NO
  // bsums. Anything else -- a forbidden local element_count/SEW/LMUL/policy attr,
  // or an unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_qs_byte_offset" || name == "weight_d_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul" || name == "minimum_vlen";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.tq2_0_q8_k_ternary_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded FUSED 2-bit ternary super-block "
                "integer-core attributes 'kind', 'scale_model', 'qk', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_qs_byte_offset', 'weight_d_byte_offset', "
                "'activation_d_byte_offset', 'activation_quant_byte_offset', "
                "'integer_core_lmul', and 'minimum_vlen'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_tq2_0_q8_k_ternary_core")
    return emitOpError()
           << "currently supports only kind \"ggml_tq2_0_q8_k_ternary_core\" for "
              "the bounded ggml TQ2_0 x Q8_K super-block FUSED 2-bit ternary "
              "scalar integer-core typed surface";
  if (getScaleModel() !=
      "ternary-2bit-fused-plane-single-fp16-scale-i32-domain")
    return emitOpError()
           << "requires scale_model "
              "\"ternary-2bit-fused-plane-single-fp16-scale-i32-domain\" for "
              "the ggml TQ2_0 x Q8_K super-block FUSED 2-bit ternary scalar "
              "integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // block_tq2_0 stride 66 (qs[64]@0|d@64 -- the weight LEADS, the single fp16
  // scale is the SUFFIX), block_q8_K stride 292 (d@0|qs@4). Pin them so a
  // malformed typed body cannot lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml TQ2_0 x "
                            "Q8_K super-block FUSED 2-bit ternary integer-core "
                            "route";
  if (getWeightBlockStride() != 66)
    return emitOpError()
           << "requires weight_block_stride == 66 (sizeof block_tq2_0 = qs[64] "
              "+ fp16 d) for the ggml TQ2_0 x Q8_K super-block FUSED 2-bit "
              "ternary integer-core route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml TQ2_0 x Q8_K super-block FUSED 2-bit ternary "
              "integer-core route";
  if (getWeightQsByteOffset() != 0)
    return emitOpError()
           << "requires weight_qs_byte_offset == 0 (the 64 packed 2-bit-weight "
              "qs bytes LEAD block_tq2_0) for the ggml TQ2_0 x Q8_K super-block "
              "FUSED 2-bit ternary integer-core route";
  if (getWeightDByteOffset() != 64)
    return emitOpError()
           << "requires weight_d_byte_offset == 64 (the fp16 super-block scale "
              "d FOLLOWS qs[64] -- d is at the END of block_tq2_0) for the ggml "
              "TQ2_0 x Q8_K super-block FUSED 2-bit ternary integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 q8_K scale d "
              "leads the block) for the ggml TQ2_0 x Q8_K super-block FUSED "
              "2-bit ternary integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml TQ2_0 x Q8_K super-block FUSED 2-bit ternary "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (sumi) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (sumi)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_tq2_0 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getSumi().getType().isInteger(32))
    return emitOpError()
           << "requires the result (sumi, the per-super-block fused 2-bit "
              "ternary*q8 integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml TQ2_0 x Q8_K super-block FUSED 2-bit "
              "ternary scalar integer core";

  if (static_cast<bool>(getIntegerCoreLmul()) !=
      static_cast<bool>(getMinimumVlen()))
    return emitOpError()
           << "requires integer_core_lmul and minimum_vlen to be both absent "
              "or both present";
  if (std::optional<llvm::StringRef> anchor = getIntegerCoreLmul())
    if (*anchor != "m1" && *anchor != "m2")
      return emitOpError()
             << "only accepts integer_core_lmul \"m1\" or \"m2\"; got \""
             << *anchor << "\"";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotTQ10Q8KTernaryCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // ternary-base3 single-fp16-scale integer-core scale model, and the
  // super-block-format structural facts the integer core reads (the 48 packed
  // base-3 qs bytes @0, the 4 base-3 qh bytes @48, the fp16 weight scale d @52 --
  // d is at the END of block_tq1_0, the qh array is the new structural fact vs
  // tq2_0 -- the fp32 activation scale d @0, qs @4). tq1_0 is BASE-3
  // TERNARY with one fixed realized body and NO scales[16], NO
  // per-sub-block scale, NO min term, NO dmin, NO bsums. Anything else -- a
  // forbidden local element_count/SEW/LMUL/policy attr, or an unexpected name --
  // is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_qs_byte_offset" ||
           name == "weight_qh_byte_offset" || name == "weight_d_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.tq1_0_q8_k_ternary_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded BASE-3 ternary super-block "
                "integer-core attributes 'kind', 'scale_model', 'qk', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_qs_byte_offset', 'weight_qh_byte_offset', "
                "'weight_d_byte_offset', 'activation_d_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_tq1_0_q8_k_ternary_core")
    return emitOpError()
           << "currently supports only kind \"ggml_tq1_0_q8_k_ternary_core\" for "
              "the bounded ggml TQ1_0 x Q8_K super-block BASE-3 ternary scalar "
              "integer-core typed surface";
  if (getScaleModel() != "ternary-base3-single-fp16-scale-i32-domain")
    return emitOpError()
           << "requires scale_model "
              "\"ternary-base3-single-fp16-scale-i32-domain\" for the ggml TQ1_0 "
              "x Q8_K super-block BASE-3 ternary scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // block_tq1_0 stride 54 (qs[48]@0|qh[4]@48|d@52 -- the two base-3 weight
  // arrays LEAD, the single fp16 scale is the SUFFIX), block_q8_K stride 292
  // (d@0|qs@4). Pin them so a malformed typed body cannot lower under the
  // super-block dot emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml TQ1_0 x "
                            "Q8_K super-block BASE-3 ternary integer-core route";
  if (getWeightBlockStride() != 54)
    return emitOpError()
           << "requires weight_block_stride == 54 (sizeof block_tq1_0 = qs[48] "
              "+ qh[4] + fp16 d) for the ggml TQ1_0 x Q8_K super-block BASE-3 "
              "ternary integer-core route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml TQ1_0 x Q8_K super-block BASE-3 ternary integer-core "
              "route";
  if (getWeightQsByteOffset() != 0)
    return emitOpError()
           << "requires weight_qs_byte_offset == 0 (the 48 packed base-3 qs "
              "bytes LEAD block_tq1_0) for the ggml TQ1_0 x Q8_K super-block "
              "BASE-3 ternary integer-core route";
  if (getWeightQhByteOffset() != 48)
    return emitOpError()
           << "requires weight_qh_byte_offset == 48 (the 4 base-3 qh bytes "
              "FOLLOW qs[48]) for the ggml TQ1_0 x Q8_K super-block BASE-3 "
              "ternary integer-core route";
  if (getWeightDByteOffset() != 52)
    return emitOpError()
           << "requires weight_d_byte_offset == 52 (the fp16 super-block scale "
              "d FOLLOWS qs[48]+qh[4] -- d is at the END of block_tq1_0) for "
              "the ggml TQ1_0 x Q8_K super-block BASE-3 ternary integer-core "
              "route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 q8_K scale d "
              "leads the block) for the ggml TQ1_0 x Q8_K super-block BASE-3 "
              "ternary integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml TQ1_0 x Q8_K super-block BASE-3 ternary "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (sumi) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (sumi)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_tq1_0 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getSumi().getType().isInteger(32))
    return emitOpError()
           << "requires the result (sumi, the per-super-block base-3 "
              "ternary*q8 integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml TQ1_0 x Q8_K super-block BASE-3 ternary "
              "scalar integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ4XSQ8KCodebookCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // signed-6-bit-scale codebook-gather FLOAT-domain (NO min) scale model, the
  // iq4_xs super-block-format structural facts the integer core reads (the fp16
  // weight scale d @0, scales_h @2, scales_l[4] @4, qs[128] @8, the q8_K fp32 d @0,
  // qs @4), and the 16-entry non-linear int8 CODEBOOK (the SAME kvalues_iq4nl[16]
  // as iq4_nl, a structural fact like the strides/offsets). iq4_xs is SYMMETRIC --
  // there is NO min term, NO dmin, NO bsums. Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected
  // fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_d_byte_offset" ||
           name == "weight_scales_h_byte_offset" ||
           name == "weight_scales_l_byte_offset" ||
           name == "weight_qs_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" || name == "codebook";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq4_xs_q8_k_codebook_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded super-block codebook integer-core "
                "attributes 'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_d_byte_offset', 'weight_scales_h_byte_offset', "
                "'weight_scales_l_byte_offset', 'weight_qs_byte_offset', "
                "'activation_d_byte_offset', 'activation_quant_byte_offset', "
                "and 'codebook'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq4_xs_q8_k_codebook_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq4_xs_q8_k_codebook_core\" "
              "for the bounded ggml IQ4_XS x Q8_K super-block CODEBOOK scalar "
              "integer-core typed surface";
  if (getScaleModel() !=
      "per-sub-block-signed-6bit-scale-codebook-gather-float-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-sub-block-signed-6bit-scale-codebook-gather-float-domain\" "
              "for the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar "
              "integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256,
  // 8 sub-blocks of 32 elements, block_iq4_xs stride 136 (d@0|scales_h@2|
  // scales_l[4]@4|qs[128]@8), block_q8_K stride 292 (d@0|qs@4|bsums@260 unused).
  // Pin them so a malformed typed body cannot lower under the integer-core
  // emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ4_XS x "
                            "Q8_K super-block CODEBOOK scalar integer-core route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block scale boundary) "
              "for the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar "
              "integer-core route";
  if (getWeightBlockStride() != 136)
    return emitOpError()
           << "requires weight_block_stride == 136 (sizeof block_iq4_xs) for "
              "the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar integer-core "
              "route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar integer-core "
              "route";
  if (getWeightDByteOffset() != 0)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (the fp16 super-block scale d "
              "leads block_iq4_xs) for the ggml IQ4_XS x Q8_K super-block "
              "CODEBOOK scalar integer-core route";
  if (getWeightScalesHByteOffset() != 2)
    return emitOpError()
           << "requires weight_scales_h_byte_offset == 2 (the uint16 scales_h "
              "follows d) for the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar "
              "integer-core route";
  if (getWeightScalesLByteOffset() != 4)
    return emitOpError()
           << "requires weight_scales_l_byte_offset == 4 (the 4 scales_l bytes "
              "follow d+scales_h) for the ggml IQ4_XS x Q8_K super-block "
              "CODEBOOK scalar integer-core route";
  if (getWeightQsByteOffset() != 8)
    return emitOpError()
           << "requires weight_qs_byte_offset == 8 (the 128 packed nibble bytes "
              "follow d+scales_h+scales_l[4]) for the ggml IQ4_XS x Q8_K "
              "super-block CODEBOOK scalar integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 q8_K scale d "
              "leads the block) for the ggml IQ4_XS x Q8_K super-block CODEBOOK "
              "scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 "
              "d) for the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar "
              "integer-core route";

  // The codebook is the load-bearing structural fact of the codebook class: it
  // MUST carry EXACTLY 16 int8 entries (one per nibble index [0,15], the SAME
  // kvalues_iq4nl[16] table iq4_nl uses). A wrong size cannot index the nibbles
  // and is rejected fail-closed (I7). The entry VALUES are NOT pinned here --
  // they are a genuine structural input the gather realizes (a wrong-but-well-
  // sized codebook is a legal-but-different kernel, which is what the
  // negative-control validation exercises).
  if (getCodebook().size() != 16)
    return emitOpError()
           << "requires codebook to carry exactly 16 int8 entries (the "
              "non-linear nibble->int8 lookup table kvalues_iq4nl[16], shared "
              "with iq4_nl); got "
           << getCodebook().size();

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (an UNUSED structural placeholder mirroring the sibling grid-core
  // bricks' scalar-state arity) -- NO output pointer (iq4_xs's per-super-block
  // contribution is a running fp32 fold with no single scalar state, wholly
  // emitter-inlined).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (the unused per-super-block placeholder)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq4_xs byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getPartial().getType().isInteger(32))
    return emitOpError()
           << "requires the result (the unused per-super-block placeholder) to "
              "be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ4_XS x Q8_K super-block CODEBOOK scalar "
              "integer core";

  return mlir::success();
}

// NOTE: GgmlBlockDotIQ4XSQ8KOp::verify was RETIRED at the iq4_xs flip (C_construct
// 23->24) with the monolith op def; the iq4_xs codebook-core brick verifier
// (GgmlBlockDotIQ4XSQ8KCodebookCoreOp::verify, above) is the live bounded-surface gate.

mlir::LogicalResult GgmlBlockDotNVFP4Q80CodebookCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // UE4M3 half-form per-sub-block weight scale model, the nvfp4 super-block-format
  // structural facts the integer core reads (the four UE4M3 scales @0..3, the FP4
  // nibbles @4, the block_q8_0 quants @2 + high half @8), the 16-entry DOUBLED int8
  // CODEBOOK (the SAME kvalues_mxfp4[16] as mxfp4), and the bounded shape knob.
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "qk_sub" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "activation_high_byte_offset" || name == "codebook" ||
           name == "integer_core_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.nvfp4_q8_0_codebook_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded super-block codebook integer-core "
                "attributes 'kind', 'scale_model', 'qk', 'qk_sub', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_quant_byte_offset', 'activation_quant_byte_offset', "
                "'activation_high_byte_offset', 'codebook', and "
                "'integer_core_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_nvfp4_q8_0_codebook_core")
    return emitOpError()
           << "currently supports only kind \"ggml_nvfp4_q8_0_codebook_core\" "
              "for the bounded ggml NVFP4 x Q8_0 super-block CODEBOOK scalar "
              "integer-core typed surface";
  // The UE4M3 half-form scale convention is the load-bearing distinction between
  // nvfp4 and mxfp4 (the codebook is the SAME DOUBLED int8 e2m1 set, so the block
  // scale is the UE4M3 decode * 0.5f, the HALF form). Pin it so a wrong scale
  // convention (the full decode without *0.5f, or a signed E4M3 misread) is
  // rejected fail-closed.
  if (getScaleModel() != "ue4m3-half-per-sub-block")
    return emitOpError()
           << "requires scale_model \"ue4m3-half-per-sub-block\" for the ggml "
              "NVFP4 x Q8_0 super-block CODEBOOK scalar integer-core route (the "
              "UE4M3 unsigned fp8 decode * 0.5f matching the doubled int8 e2m1 "
              "codebook)";
  // ggml's externally-defined super-block format (ggml-common.h): QK_NVFP4 == 64,
  // QK_NVFP4_SUB == 16, block_nvfp4 = { uint8_t d[4]; uint8_t qs[32] } stride 36
  // (four UE4M3 sub-block scales + 32 packed FP4 nibble bytes), block_q8_0 stride
  // 34, the weight nibbles at byte offset +4 (after the four UE4M3 scale bytes),
  // the q8 quants at +2, the per-sub-block q8 high half at +8. Pin them so a
  // malformed typed body cannot lower under the integer-core emission.
  if (getQk() != 64)
    return emitOpError() << "requires qk == 64 (QK_NVFP4) for the ggml NVFP4 x "
                            "Q8_0 super-block CODEBOOK scalar integer-core route";
  if (getQkSub() != 16)
    return emitOpError()
           << "requires qk_sub == 16 (QK_NVFP4_SUB, the per-scale sub-block "
              "size) for the ggml NVFP4 x Q8_0 super-block CODEBOOK scalar "
              "integer-core route";
  if (getWeightBlockStride() != 36)
    return emitOpError()
           << "requires weight_block_stride == 36 (sizeof block_nvfp4: four "
              "UE4M3 scale bytes + 32 packed FP4 nibble bytes) for the ggml "
              "NVFP4 x Q8_0 super-block CODEBOOK scalar integer-core route";
  if (getActivationBlockStride() != 34)
    return emitOpError()
           << "requires activation_block_stride == 34 (sizeof block_q8_0) for "
              "the ggml NVFP4 x Q8_0 super-block CODEBOOK scalar integer-core "
              "route";
  if (getWeightQuantByteOffset() != 4)
    return emitOpError()
           << "requires weight_quant_byte_offset == 4 (the FP4 nibbles follow "
              "the four UE4M3 sub-block scale bytes) for the ggml NVFP4 x Q8_0 "
              "super-block CODEBOOK scalar integer-core route";
  if (getActivationQuantByteOffset() != 2)
    return emitOpError()
           << "requires activation_quant_byte_offset == 2 (the q8 quants follow "
              "the inline fp16 scale) for the ggml NVFP4 x Q8_0 super-block "
              "CODEBOOK scalar integer-core route";
  if (getActivationHighByteOffset() != 8)
    return emitOpError()
           << "requires activation_high_byte_offset == 8 (the per-sub-block q8 "
              "high half is QK_NVFP4_SUB/2 lanes on) for the ggml NVFP4 x Q8_0 "
              "super-block CODEBOOK scalar integer-core route";

  // The codebook is the load-bearing structural fact of the codebook class: it
  // MUST carry EXACTLY 16 int8 entries (one per FP4 nibble index [0,15], the SAME
  // kvalues_mxfp4[16] table mxfp4 uses). A wrong size cannot index the nibbles and
  // is rejected fail-closed (I7). The entry VALUES are NOT pinned here -- they are
  // a genuine structural input the gather realizes (a wrong-but-well-sized codebook
  // is a legal-but-different kernel, which is what the negative-control validation
  // exercises).
  if (getCodebook().size() != 16)
    return emitOpError()
           << "requires codebook to carry exactly 16 int8 entries (the FP4 e2m1 "
              "nibble->int8 lookup table kvalues_mxfp4[16]); got "
           << getCodebook().size();

  // The codebook gather's legal integer-core anchor is a VLEN-CAPABILITY fact, not a
  // fixed "m1" (the SAME rule as the mxfp4 sibling): to index ALL codebook.size()
  // table entries the broadcast `values` register's i8 gather VLMAX must be >=
  // codebook.size(), and WHICH anchor reaches that MOVES with VLEN. Recomputed from
  // the SAME getRVVStripVLMAXElements truth source the codebook emitter's anchor
  // formula (getRVVCodebookGatherAnchorLMUL) selects with -- VLMAX >= codebook.size()
  // REPLACES the old `== "m1"` literal. The nvfp4 core brick carries NO minimum_vlen,
  // so it gates at the byte-exact anchor VLEN (128): only m1 -> VLMAX 16 covers a
  // 16-entry table (mf2 -> VLMAX 8 < 16), so today's schedules stay byte-identical.
  // Reject VLMAX < codebook.size() fail-closed (I7). The vwredsum destination + seed
  // stay m1 regardless of the i8 anchor.
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul()) {
    constexpr std::int64_t kCodebookByteExactMinVLEN = 128;
    std::int64_t codebookEntries =
        static_cast<std::int64_t>(getCodebook().size());
    std::int64_t gatherVLMAX = ::weft::plugin::rvv::getRVVStripVLMAXElements(
        ::weft::plugin::rvv::getRVVBlockDotStripLMUL(*coreLmul),
        ::weft::plugin::rvv::getRVVBlockDotStripSEW(*coreLmul),
        kCodebookByteExactMinVLEN);
    if (gatherVLMAX < codebookEntries)
      return emitOpError()
             << "integer_core_lmul \"" << *coreLmul << "\" cannot host the "
             << codebookEntries << "-entry codebook gather at VLEN "
             << kCodebookByteExactMinVLEN
             << ": the broadcast table register's VLMAX is " << gatherVLMAX
             << " (< " << codebookEntries
             << ", so a nibble index >= VLMAX silently reads 0). At VLEN128 the "
                "gather requires m1; a narrower anchor is legal only on a wider VLEN "
                "(mf2 reaches VLMAX 16 at VLEN256, the ggml _vl256 shape)";
    // The VLMAX >= codebook.size() fact admits m1/mf2 but ALSO any wider anchor (m2
    // -> VLMAX 32 at VLEN128). The emitter handles ONLY m1 (i16 product m2) and mf2
    // (i16 product m1): a wider anchor would be mis-widened. Restrict to the
    // emitter-supported set fail-closed (I7) -- the same guard the old m1-pin carried.
    if (*coreLmul != "m1" && *coreLmul != "mf2")
      return emitOpError()
             << "integer_core_lmul \"" << *coreLmul
             << "\" is not an emitter-supported codebook anchor: the ggml NVFP4 x "
                "Q8_0 super-block CODEBOOK emits only m1 (the VLEN128 form, i16 "
                "product m2) or mf2 (the VLEN256 _vl256 form, i16 product m1); a "
                "wider anchor would be mis-widened";
  }

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (an UNUSED structural placeholder) -- NO output pointer (nvfp4's
  // per-super-block contribution is a running fp32 fold with no single scalar
  // state, wholly emitter-inlined).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (the unused per-super-block placeholder)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_nvfp4 byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_0 byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getPartial().getType().isInteger(32))
    return emitOpError()
           << "requires the result (the unused per-super-block placeholder) to "
              "be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml NVFP4 x Q8_0 super-block CODEBOOK scalar "
              "integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ2XXSQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // aux1-scale grid-of-8-codebook signs64-sign-plane integer-core scale model, the
  // iq2_xxs super-block-format structural facts the integer core reads (the fp16 d @0,
  // the 64 uint8 INTERLEAVED index+aux bytes qs @2, the q8_K fp32 d @0, the q8_K qs @4),
  // plus the final resource shape knob integer_core_lmul + semantic minimum_vlen.
  // The FIXED 256-entry
  // iq2xxs_grid GRID-of-8 codebook and the DERIVED keven_signs_q2xs signs64 sign plane
  // are byte-exact constants of the FORMAT (keyed off the brick op identity at emit),
  // NOT carried in the IR (the signs64 sign-plane is DERIVED from the fixed ksigns
  // selector at emit, NO op-attr). Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected fail-closed
  // (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_d_byte_offset" || name == "weight_qs_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul" || name == "minimum_vlen" ||
           // A-line g-axis debake (路 B): the iq2_xxs grid sign-group count.
           name == "num_groups";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq2_xxs_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded GRID-of-8 super-block integer-core "
                "attributes 'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_d_byte_offset', 'weight_qs_byte_offset', "
                "'activation_d_byte_offset', 'activation_quant_byte_offset', "
                "'integer_core_lmul', and 'minimum_vlen'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq2_xxs_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq2_xxs_q8_k_grid_core\" "
              "for the bounded ggml IQ2_XXS x Q8_K super-block GRID-of-8 scalar "
              "integer-core typed surface";
  if (getScaleModel() !=
      "per-sub-block-aux1-scale-grid-of-8-codebook-signs64-sign-plane-int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-sub-block-aux1-scale-grid-of-8-codebook-signs64-sign-plane-"
              "int-domain\" for the ggml IQ2_XXS x Q8_K super-block GRID-of-8 "
              "scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, block_iq2_xxs stride 66 (d@0|qs[32]@2), block_q8_K
  // stride 292 (d@0|qs@4). Pin the facts so a malformed typed body cannot lower under
  // the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ2_XXS x "
                            "Q8_K super-block GRID-of-8 scalar integer-core route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ2_XXS x Q8_K super-block GRID-of-8 scalar integer-core "
              "route";
  if (getWeightBlockStride() != 66)
    return emitOpError()
           << "requires weight_block_stride == 66 (sizeof block_iq2_xxs) for the "
              "ggml IQ2_XXS x Q8_K super-block GRID-of-8 scalar integer-core "
              "route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ2_XXS x Q8_K super-block GRID-of-8 scalar integer-core "
              "route";
  if (getWeightDByteOffset() != 0)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (the fp16 d leads block_iq2_xxs) "
              "for the ggml IQ2_XXS x Q8_K super-block GRID-of-8 scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 2)
    return emitOpError()
           << "requires weight_qs_byte_offset == 2 (the uint16 qs[32] carrying the "
              "INTERLEAVED grid indices + aux pair follow the fp16 d) for the ggml "
              "IQ2_XXS x Q8_K super-block GRID-of-8 scalar integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 d leads "
              "block_q8_K) for the ggml IQ2_XXS x Q8_K super-block GRID-of-8 "
              "scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 d) "
              "for the ggml IQ2_XXS x Q8_K super-block GRID-of-8 scalar "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (bsum) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (bsum)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq2_xxs byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getBsum().getType().isInteger(32))
    return emitOpError()
           << "requires the result (bsum, the per-super-block 4-bit-scaled "
              "grid/sign integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ2_XXS x Q8_K super-block GRID-of-8 "
              "scalar integer core";

  if (static_cast<bool>(getIntegerCoreLmul()) !=
      static_cast<bool>(getMinimumVlen()))
    return emitOpError()
           << "requires integer_core_lmul and minimum_vlen to be both absent "
              "or both present";
  if (std::optional<llvm::StringRef> anchor = getIntegerCoreLmul())
    if (*anchor != "m1" && *anchor != "m2")
      return emitOpError()
             << "only accepts integer_core_lmul \"m1\" or \"m2\"; got \""
             << *anchor << "\"";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ2XSQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // per-half-explicit-scale grid-codebook signs64-sign-plane integer-core scale model,
  // the iq2_xs super-block-format structural facts the integer core reads (the fp16 d @0,
  // the 64 uint8 qs bytes @2, the explicit 4-bit scales[8] @66, the q8_K fp32 d @0, the
  // q8_K qs @4). The FIXED 512-entry iq2xs_grid codebook and the DERIVED keven_signs_q2xs
  // signs64 sign plane are byte-exact constants of the FORMAT (keyed off the brick op
  // identity at emit), NOT carried in the IR (the signs64 sign-plane is DERIVED from the
  // fixed ksigns selector at emit, NO op-attr). UNLIKE the iq2_xxs sibling there is NO
  // integer_core_lmul gearbox (fixed 16-lane per-half shape). Anything else -- a forbidden
  // local element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected
  // fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_d_byte_offset" || name == "weight_qs_byte_offset" ||
           name == "weight_scales_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           // A-line g-axis debake (路 B): the iq2_xs per-16-lane-half group count.
           name == "num_groups_per_half";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq2_xs_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded per-half-explicit-scale GRID "
                "super-block integer-core attributes 'kind', 'scale_model', "
                "'qk', 'sub_block', 'weight_block_stride', "
                "'activation_block_stride', 'weight_d_byte_offset', "
                "'weight_qs_byte_offset', 'weight_scales_byte_offset', "
                "'activation_d_byte_offset', and 'activation_quant_byte_offset'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq2_xs_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq2_xs_q8_k_grid_core\" "
              "for the bounded ggml IQ2_XS x Q8_K super-block per-half-scale "
              "GRID scalar integer-core typed surface";
  if (getScaleModel() !=
      "per-half-int4-explicit-scales-grid-codebook-signs64-sign-plane-int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-half-int4-explicit-scales-grid-codebook-signs64-sign-plane-"
              "int-domain\" for the ggml IQ2_XS x Q8_K super-block per-half-scale "
              "GRID scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, block_iq2_xs stride 74 (d@0|qs[32]@2|scales[8]@66),
  // block_q8_K stride 292 (d@0|qs@4). Pin the facts so a malformed typed body cannot
  // lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ2_XS x "
                            "Q8_K super-block per-half-scale GRID scalar "
                            "integer-core route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ2_XS x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightBlockStride() != 74)
    return emitOpError()
           << "requires weight_block_stride == 74 (sizeof block_iq2_xs) for the "
              "ggml IQ2_XS x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ2_XS x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightDByteOffset() != 0)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (the fp16 d leads block_iq2_xs) "
              "for the ggml IQ2_XS x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 2)
    return emitOpError()
           << "requires weight_qs_byte_offset == 2 (the uint16 qs[32] carrying "
              "the 9-bit grid indices + 7-bit sign selectors follow the fp16 d) "
              "for the ggml IQ2_XS x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightScalesByteOffset() != 66)
    return emitOpError()
           << "requires weight_scales_byte_offset == 66 (the uint8 scales[8] "
              "follow the 64-byte qs[32]) for the ggml IQ2_XS x Q8_K super-block "
              "per-half-scale GRID scalar integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 d leads "
              "block_q8_K) for the ggml IQ2_XS x Q8_K super-block per-half-scale "
              "GRID scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 d) "
              "for the ggml IQ2_XS x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (bsum) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (bsum)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq2_xs byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getBsum().getType().isInteger(32))
    return emitOpError()
           << "requires the result (bsum, the per-super-block per-half-scaled "
              "grid/sign integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ2_XS x Q8_K super-block per-half-scale "
              "GRID scalar integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ2SQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // per-half-explicit-scale grid-codebook qh-plane-explicit-signs integer-core scale
  // model, the iq2_s super-block-format structural facts the integer core reads (the
  // fp16 d @0, the 32 index bytes @2, the explicit 32 sign bytes @34 = qs+QK_K/8, the
  // qh-bit plane qh @66, the explicit 4-bit scales[8] @74, the q8_K fp32 d @0, the q8_K
  // qs @4). The FIXED 1024-entry iq2s_grid codebook and the UNIVERSAL signs256 sign
  // plane are byte-exact constants of the FORMAT (keyed off the brick op identity at
  // emit), NOT carried in the IR (iq2_s has NO ksigns selector -- the signs are explicit
  // bytes and the signs256 plane is the definitional 8-bit-to-per-lane +-1 expansion).
  // Like iq2_xs there is NO integer_core_lmul gearbox (fixed 16-lane per-half shape).
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_d_byte_offset" || name == "weight_qs_byte_offset" ||
           name == "weight_signs_byte_offset" ||
           name == "weight_qh_byte_offset" ||
           name == "weight_scales_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           // A-line g-axis debake (路 B): the iq2_s grid group counts.
           name == "groups_per_sub" || name == "num_groups_per_half";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq2_s_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded per-half-explicit-scale GRID "
                "super-block integer-core attributes 'kind', 'scale_model', "
                "'qk', 'sub_block', 'weight_block_stride', "
                "'activation_block_stride', 'weight_d_byte_offset', "
                "'weight_qs_byte_offset', 'weight_signs_byte_offset', "
                "'weight_qh_byte_offset', 'weight_scales_byte_offset', "
                "'activation_d_byte_offset', and 'activation_quant_byte_offset'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq2_s_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq2_s_q8_k_grid_core\" "
              "for the bounded ggml IQ2_S x Q8_K super-block per-half-scale "
              "GRID scalar integer-core typed surface";
  if (getScaleModel() !=
      "per-half-int4-explicit-scales-grid-codebook-qh-plane-explicit-signs-int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-half-int4-explicit-scales-grid-codebook-qh-plane-explicit-"
              "signs-int-domain\" for the ggml IQ2_S x Q8_K super-block "
              "per-half-scale GRID scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, block_iq2_s stride 82 (d@0|qs[64]@2|qh[8]@66|
  // scales[8]@74; the qs[64] array holds 32 index bytes @2 then 32 sign bytes @34),
  // block_q8_K stride 292 (d@0|qs@4). Pin the facts so a malformed typed body cannot
  // lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ2_S x "
                            "Q8_K super-block per-half-scale GRID scalar "
                            "integer-core route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ2_S x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightBlockStride() != 82)
    return emitOpError()
           << "requires weight_block_stride == 82 (sizeof block_iq2_s) for the "
              "ggml IQ2_S x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ2_S x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightDByteOffset() != 0)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (the fp16 d leads block_iq2_s) "
              "for the ggml IQ2_S x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 2)
    return emitOpError()
           << "requires weight_qs_byte_offset == 2 (the uint8 qs[64] follow d; "
              "the first 32 bytes are grid index bytes) for the ggml IQ2_S x "
              "Q8_K super-block per-half-scale GRID scalar integer-core route";
  if (getWeightSignsByteOffset() != 34)
    return emitOpError()
           << "requires weight_signs_byte_offset == 34 (the explicit sign bytes "
              "live INSIDE qs[64] at qs+QK_K/8 = 2+32) for the ggml IQ2_S x "
              "Q8_K super-block per-half-scale GRID scalar integer-core route";
  if (getWeightQhByteOffset() != 66)
    return emitOpError()
           << "requires weight_qh_byte_offset == 66 (the uint8 qh[8] qh-bit "
              "plane follow the 64-byte qs) for the ggml IQ2_S x Q8_K "
              "super-block per-half-scale GRID scalar integer-core route";
  if (getWeightScalesByteOffset() != 74)
    return emitOpError()
           << "requires weight_scales_byte_offset == 74 (the uint8 scales[8] "
              "follow qh[8]) for the ggml IQ2_S x Q8_K super-block "
              "per-half-scale GRID scalar integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 d leads "
              "block_q8_K) for the ggml IQ2_S x Q8_K super-block per-half-scale "
              "GRID scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 d) "
              "for the ggml IQ2_S x Q8_K super-block per-half-scale GRID scalar "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (bsum) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (bsum)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq2_s byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getBsum().getType().isInteger(32))
    return emitOpError()
           << "requires the result (bsum, the per-super-block per-half-scaled "
              "grid/sign integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ2_S x Q8_K super-block per-half-scale "
              "GRID scalar integer core";

  return mlir::success();
}

mlir::LogicalResult GgmlBlockDotIQ3SQ8KGridCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // explicit-scale grid-of-4-codebook qh-plane explicit-signs integer-core scale
  // model, and the iq3_s super-block-format structural facts the integer core reads
  // (the fp16 d @0, the 64 uint8 grid-index bytes qs @2, the 8 qh-plane bytes @66, the
  // 32 EXPLICIT sign bytes @74, the 4 packed-4-bit scale bytes @106, the q8_K fp32 d
  // @0, the q8_K qs @4). The FIXED 512-entry iq3s_grid GRID-of-4 codebook is a
  // byte-exact constant of the FORMAT (keyed off the brick op identity at emit), NOT
  // carried in the IR; iq3_s has NO ksigns plane (the signs are an explicit memory
  // region). Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or
  // an unexpected name -- is rejected fail-closed (I7).
  auto isAllowedBlockDotAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "scale_model" || name == "qk" ||
           name == "sub_block" || name == "weight_block_stride" ||
           name == "activation_block_stride" ||
           name == "weight_d_byte_offset" || name == "weight_qs_byte_offset" ||
           name == "weight_qh_byte_offset" ||
           name == "weight_signs_byte_offset" ||
           name == "weight_scales_byte_offset" ||
           name == "activation_d_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           // A-line g-axis debake (路 B): the iq3_s grid sub-structure counts.
           name == "num_groups" || name == "indices_per_sub_block" ||
           name == "signs_per_sub_block" || name == "group_lanes";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.iq3_s_q8_k_grid_core keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedBlockDotAttr(attrName))
      return emitOpError()
             << "only accepts the bounded GRID-of-4 super-block integer-core "
                "attributes 'kind', 'scale_model', 'qk', 'sub_block', "
                "'weight_block_stride', 'activation_block_stride', "
                "'weight_d_byte_offset', 'weight_qs_byte_offset', "
                "'weight_qh_byte_offset', 'weight_signs_byte_offset', "
                "'weight_scales_byte_offset', 'activation_d_byte_offset', and "
                "'activation_quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_iq3_s_q8_k_grid_core")
    return emitOpError()
           << "currently supports only kind \"ggml_iq3_s_q8_k_grid_core\" for "
              "the bounded ggml IQ3_S x Q8_K super-block GRID-of-4 scalar "
              "integer-core typed surface";
  if (getScaleModel() !=
      "per-sub-block-explicit-scale-grid-of-4-codebook-qh-plane-explicit-signs-int-domain")
    return emitOpError()
           << "requires scale_model "
              "\"per-sub-block-explicit-scale-grid-of-4-codebook-qh-plane-"
              "explicit-signs-int-domain\" for the ggml IQ3_S x Q8_K super-block "
              "GRID-of-4 scalar integer-core route";
  // ggml's externally-defined super-block format (ggml-common.h): QK_K == 256, 8
  // sub-blocks of 32 elements, block_iq3_s stride 110 (d@0|qs[64]@2|qh[8]@66|
  // signs[32]@74|scales[4]@106), block_q8_K stride 292 (d@0|qs@4). Pin the facts so a
  // malformed typed body cannot lower under the integer-core emission.
  if (getQk() != 256)
    return emitOpError() << "requires qk == 256 (QK_K) for the ggml IQ3_S x "
                            "Q8_K super-block GRID-of-4 scalar integer-core route";
  if (getSubBlock() != 32)
    return emitOpError()
           << "requires sub_block == 32 (32-element sub-block boundary) for the "
              "ggml IQ3_S x Q8_K super-block GRID-of-4 scalar integer-core "
              "route";
  if (getWeightBlockStride() != 110)
    return emitOpError()
           << "requires weight_block_stride == 110 (sizeof block_iq3_s) for the "
              "ggml IQ3_S x Q8_K super-block GRID-of-4 scalar integer-core "
              "route";
  if (getActivationBlockStride() != 292)
    return emitOpError()
           << "requires activation_block_stride == 292 (sizeof block_q8_K) for "
              "the ggml IQ3_S x Q8_K super-block GRID-of-4 scalar integer-core "
              "route";
  if (getWeightDByteOffset() != 0)
    return emitOpError()
           << "requires weight_d_byte_offset == 0 (the fp16 d leads block_iq3_s) "
              "for the ggml IQ3_S x Q8_K super-block GRID-of-4 scalar "
              "integer-core route";
  if (getWeightQsByteOffset() != 2)
    return emitOpError()
           << "requires weight_qs_byte_offset == 2 (the 64 uint8 grid-index qs "
              "bytes follow the fp16 d) for the ggml IQ3_S x Q8_K super-block "
              "GRID-of-4 scalar integer-core route";
  if (getWeightQhByteOffset() != 66)
    return emitOpError()
           << "requires weight_qh_byte_offset == 66 (the 8 uint8 qh-bit plane "
              "bytes follow d + the 64 grid-index bytes; each injects bit 8 of "
              "the sub-block's grid indices) for the ggml IQ3_S x Q8_K "
              "super-block GRID-of-4 scalar integer-core route";
  if (getWeightSignsByteOffset() != 74)
    return emitOpError()
           << "requires weight_signs_byte_offset == 74 (the 32 EXPLICIT uint8 "
              "sign bytes follow qh[8]; 4 sign bytes per sub-block, NO ksigns "
              "plane) for the ggml IQ3_S x Q8_K super-block GRID-of-4 scalar "
              "integer-core route";
  if (getWeightScalesByteOffset() != 106)
    return emitOpError()
           << "requires weight_scales_byte_offset == 106 (the 4 uint8 scale "
              "bytes follow signs[32]; two packed 4-bit scales per byte) for the "
              "ggml IQ3_S x Q8_K super-block GRID-of-4 scalar integer-core route";
  if (getActivationDByteOffset() != 0)
    return emitOpError()
           << "requires activation_d_byte_offset == 0 (the fp32 d leads "
              "block_q8_K) for the ggml IQ3_S x Q8_K super-block GRID-of-4 "
              "scalar integer-core route";
  if (getActivationQuantByteOffset() != 4)
    return emitOpError()
           << "requires activation_quant_byte_offset == 4 (qs follow the fp32 d) "
              "for the ggml IQ3_S x Q8_K super-block GRID-of-4 scalar "
              "integer-core route";

  // The OPTIONAL loop-form `block_index` operand adds a 5th operand (the
  // per-super-block induction variable). Absent = the standalone 4-operand
  // single-super-block form; present = the loop form. The op produces ONE scalar
  // i32 result (bsum) -- NO output pointer (the scalar state is an SSA result).
  unsigned expectedOperands = getBlockIndex() ? 5 : 4;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one runtime element-count runtime ABI operand, one !weft_rvv.vl "
              "operand, an OPTIONAL `block_index` induction operand, and one "
              "scalar i32 result (bsum)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_iq3_s byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  if (!getBsum().getType().isInteger(32))
    return emitOpError()
           << "requires the result (bsum, the per-super-block 4-bit-scaled "
              "grid/sign integer dot) to be scalar i32";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml IQ3_S x Q8_K super-block GRID-of-4 "
              "scalar integer core";

  return mlir::success();
}

// NOTE: GgmlBlockDotIQ3SQ8KOp::verify was RETIRED at the iq3_s flip (C_construct
// 22->23) with the monolith op def; the iq3_s grid-core brick verifier
// (GgmlBlockDotIQ3SQ8KGridCoreOp::verify, above) is the live bounded-surface gate.

// NOTE: GgmlBlockDotIQ1MQ8KOp::verify was RETIRED at the iq1_m flip (L3) with the
// monolith op def; the iq1_m grid-core brick verifier
// (GgmlBlockDotIQ1MQ8KGridCoreOp::verify) is the live bounded-surface gate.

// M-FLAT forward-elementwise scaffold verifiers (line C, ① 之后). The typed
// elementwise strip-loop op is the forward-pass sibling of the flat block-dot
// loop op (RVVDialectWideningOps.cpp TypedFlatBlockDotLoopBodyOp::verify): it
// carries the outer `for (i=0; i<n; i+=vlmax)` strip loop + a single-block
// region whose entry arg is the strip induction variable and whose per-strip
// work is a separate typed core brick. The map model carries NO loop-carried
// accumulator (the yield names no operand); a bounded reduce model is later.
mlir::LogicalResult TypedElementwiseLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  if (getKind() != "typed_elementwise_loop_body")
    return emitOpError()
           << "currently supports only kind \"typed_elementwise_loop_body\" for "
              "the bounded forward-pass elementwise strip-loop surface";
  // reduce_map_model fixes the loop shape: "map" is the pure elementwise map (no
  // loop-carried accumulator, region carries only the strip index); "reduce"
  // carries a loop-carried accumulator (region carries strip index + acc, the
  // yield names the updated acc) for the row folds (rms_norm's Σx²). Any other
  // spelling fails closed (I7).
  llvm::StringRef reduceMapModel = getReduceMapModel();
  const bool isReduceModel = reduceMapModel == "reduce";
  const bool isRotateModel = reduceMapModel == "rotate";
  if (reduceMapModel != "map" && !isReduceModel && !isRotateModel)
    return emitOpError()
           << "currently supports only reduce_map_model \"map\" (the pure "
              "elementwise per-lane map with no loop-carried accumulator), "
              "\"reduce\" (a loop-carried accumulator for the row folds), or "
              "\"rotate\" (a per-pair scalar loop with a loop-carried f32 "
              "recurrence -- rope's theta); got \""
           << reduceMapModel << "\"";
  // element_sew currently pins the f32 (SEW=32) strip; other widths are later.
  if (getElementSewAttr().getInt() != 32)
    return emitOpError()
           << "currently supports only element_sew 32 (the f32 elementwise "
              "strip); got "
           << getElementSewAttr().getInt();
  // The optional strip-LMUL is a bounded resource/scheduling fact (the *how*):
  // the f32 strip anchors at m1/m2/m4/m8 (default m8, ggml's apply path). All
  // are byte-exact (bare per-lane multiply; the runtime vsetvl re-strips for any
  // VLEN). Any other spelling fails closed (I7).
  if (std::optional<llvm::StringRef> stripLmul = getStripLmul()) {
    if (*stripLmul != "m1" && *stripLmul != "m2" && *stripLmul != "m4" &&
        *stripLmul != "m8")
      return emitOpError()
             << "only accepts strip_lmul \"m1\", \"m2\", \"m4\", or \"m8\"; got "
                "\""
             << *stripLmul << "\"";
  }

  if (op->getNumOperands() != 3 || op->getNumResults() != 0)
    return emitOpError()
           << "requires two f32 buffer/scalar runtime ABI operands and one "
              "runtime element-count runtime ABI operand, and no results (the "
              "per-strip store is the sink)";

  // The two leading operands bind runtime ABI values (the forward operator's f32
  // in/out buffers and/or the scalar broadcast); the SPECIFIC C types are pinned
  // by the per-op map core brick verifier -- scale's elementwise_scale_map (y[]
  // 'float *' + v 'float'), silu's elementwise_silu_map (x[] 'const float *' +
  // y[] 'float *'). The shared loop op stays GENERIC over the map family (I5: it
  // owns the strip-loop SHAPE + the reduce/map model, never the per-op ABI dtype
  // authority), so silu reuses it unchanged.
  RuntimeABIValueOp bufferBinding =
      getBuffer().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp scalarBinding =
      getScalar().getDefiningOp<RuntimeABIValueOp>();
  if (!bufferBinding || !scalarBinding)
    return emitOpError()
           << "requires the two leading runtime ABI operands to bind "
              "weft_rvv.runtime_abi_value ops (the forward operator's f32 in/out "
              "buffers and/or scalar; the map core brick pins the exact C types)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // Region structure: the strip_index induction variable (index) is region
  // argument 0 for BOTH models; the "reduce" model adds a SECOND argument -- the
  // loop-carried f64 accumulator (region argument 1) -- and the yield names the
  // updated accumulator. The map model carries only strip_index and a
  // no-operand yield.
  mlir::Block &block = getBody().front();
  const bool isCarriedModel = isReduceModel || isRotateModel;
  const unsigned expectedArgs = isCarriedModel ? 2 : 1;
  if (block.getNumArguments() != expectedArgs)
    return emitOpError()
           << "requires the region to carry exactly " << expectedArgs
           << (isRotateModel
                   ? " entry arguments: the pair_index induction variable and "
                     "the loop-carried f32 theta recurrence"
                   : isReduceModel
                         ? " entry arguments: the strip_index induction variable "
                           "and the loop-carried f64 accumulator"
                         : " entry argument: the strip_index induction variable");
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (strip_index) to be "
              "index-typed (the strip induction variable)";
  // The reduce model's loop-carried accumulator (region arg 1) is EITHER the f64
  // scalar (rms_norm's Σx² scalar-double ascending fold) OR the
  // !weft_rvv.vector<f64, "m1"> WIDENING accumulator (soft_max's
  // vfwredusum_vs_f32m2_f64m1 Σe^x fold, ggml's vfloat64m1_t vsum). Any other
  // type fails closed (I7).
  if (isReduceModel) {
    mlir::Type accType = block.getArgument(1).getType();
    if (!accType.isF64() && !isGenericRVVVectorF64M1(accType))
      return emitOpError()
             << "requires the reduce model's second region argument to be the "
                "loop-carried accumulator: the f64 scalar (rms_norm's Σx² "
                "ascending fold) or the !weft_rvv.vector<f64, \"m1\"> widening "
                "accumulator (soft_max's vfwredusum Σe^x fold)";
  }
  // The rotate model's loop-carried recurrence (region arg 1) is the f32 scalar
  // theta (rope's `theta *= theta_scale` per-pair recurrence). Any other type
  // fails closed (I7).
  if (isRotateModel && !block.getArgument(1).getType().isF32())
    return emitOpError()
           << "requires the rotate model's second region argument to be the "
              "loop-carried f32 theta recurrence (rope's scalar angle stepped "
              "theta *= theta_scale per pair)";

  TypedElementwiseLoopYieldOp yield =
      block.empty()
          ? TypedElementwiseLoopYieldOp()
          : llvm::dyn_cast<TypedElementwiseLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_elementwise_loop_yield";
  // The yield's carried-value cardinality tracks the model (the yield verifier
  // pins the f64 acc type + the reduce-model tie).
  const unsigned expectedYield = isCarriedModel ? 1 : 0;
  if (yield.getAccNext().size() != expectedYield)
    return emitOpError()
           << (isRotateModel
                   ? "rotate model requires the loop yield to carry the updated "
                     "f32 theta recurrence (one operand)"
                   : isReduceModel
                         ? "reduce model requires the loop yield to carry the "
                           "updated accumulator (one operand)"
                         : "map model requires the loop yield to carry no "
                           "operand");

  return mlir::success();
}

mlir::LogicalResult TypedElementwiseLoopYieldOp::verify() {
  // The yield's carried-value cardinality tracks the enclosing loop op's model:
  // the "map" model carries no loop-carried value (0 operands); the "reduce"
  // model carries the updated f64 accumulator (1 operand). The HasParent trait
  // pins the enclosing loop op; the loop-body verifier cross-checks the count.
  auto parent = getOperation()->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return mlir::success();
  const bool isReduceModel = parent.getReduceMapModel() == "reduce";
  const bool isRotateModel = parent.getReduceMapModel() == "rotate";
  if (isReduceModel) {
    // The carried accumulator is the f64 scalar (rms_norm) OR the
    // !weft_rvv.vector<f64, "m1"> widening accumulator (soft_max), matching the
    // loop-body op's region-arg type.
    if (getAccNext().size() != 1 ||
        (!getAccNext()[0].getType().isF64() &&
         !isGenericRVVVectorF64M1(getAccNext()[0].getType())))
      return emitOpError()
             << "reduce model requires the yield to carry exactly one "
                "loop-carried accumulator operand: the f64 scalar (rms_norm) or "
                "the !weft_rvv.vector<f64, \"m1\"> widening accumulator "
                "(soft_max)";
  } else if (isRotateModel) {
    // The carried recurrence is the f32 scalar theta (rope), matching the
    // loop-body op's region-arg type.
    if (getAccNext().size() != 1 || !getAccNext()[0].getType().isF32())
      return emitOpError()
             << "rotate model requires the yield to carry exactly one "
                "loop-carried f32 theta recurrence operand (rope's stepped "
                "angle theta *= theta_scale)";
  } else if (!getAccNext().empty()) {
    return emitOpError()
           << "map model requires the yield to carry no operand (the per-strip "
              "store is the sink)";
  }
  return mlir::success();
}

mlir::LogicalResult ElementwiseScaleMapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind + the optional
  // resource/scheduling strip-LMUL knob. A forbidden local element_count/SEW/
  // LMUL/policy attr or an unexpected name fails closed (I7). The knob is named
  // "strip_lmul" (not the with_vl/setvl "lmul" spelling), exactly as the sibling
  // block-dot bricks use "integer_core_lmul".
  auto isAllowedScaleAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "strip_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_scale_map keeps SEW/LMUL/policy on "
                "setvl/with_vl and rejects deleted local element_count metadata";
    if (!isAllowedScaleAttr(attrName))
      return emitOpError()
             << "only accepts the bounded scale-map attributes 'kind' and "
                "'strip_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_scale_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_scale_map\" for the "
              "bounded per-strip f32 in-place scale map brick";
  if (std::optional<llvm::StringRef> stripLmul = getStripLmul()) {
    if (*stripLmul != "m1" && *stripLmul != "m2" && *stripLmul != "m4" &&
        *stripLmul != "m8")
      return emitOpError()
             << "only accepts strip_lmul \"m1\", \"m2\", \"m4\", or \"m8\"; got "
                "\""
             << *stripLmul << "\"";
  }

  RuntimeABIValueOp bufferBinding =
      getBuffer().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp scalarBinding =
      getScalar().getDefiningOp<RuntimeABIValueOp>();
  if (!bufferBinding || bufferBinding.getCType() != "float *")
    return emitOpError()
           << "requires the in-place buffer operand to bind a runtime ABI value "
              "of C type 'float *' (the ggml y[] buffer read and written in "
              "place)";
  if (!scalarBinding || scalarBinding.getCType() != "float")
    return emitOpError()
           << "requires the scalar operand to bind a runtime ABI value of C "
              "type 'float' (the ggml v multiplier)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // ANTI-BYPASS (I7): the strip_index MUST be the enclosing loop op's region
  // induction variable (region argument 0), so the emit provably addresses strip
  // i (buffer + strip_index), not the loop-invariant strip 0.
  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 1 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0) so the emit addresses buffer + "
              "strip_index, not the loop-invariant strip 0 (anti-bypass)";

  return mlir::success();
}

mlir::LogicalResult ElementwiseSiluMapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind. Silu is m2-pinned (the
  // exp polynomial's mask/reinterpret types are m2-tied), so there is NO
  // resource/scheduling strip_lmul knob this map -- the ONLY allowed attr is
  // "kind". A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name fails closed (I7).
  auto isAllowedSiluAttr = [](llvm::StringRef name) { return name == "kind"; };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_silu_map keeps SEW/LMUL/policy on "
                "setvl/with_vl and rejects deleted local element_count metadata";
    if (!isAllowedSiluAttr(attrName))
      return emitOpError()
             << "only accepts the bounded silu-map attribute 'kind'; unexpected "
                "attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_silu_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_silu_map\" for the "
              "bounded per-strip f32 silu map brick";

  // The input is read-only (const float *), the output is written (float *) --
  // silu reads x[] and writes y[] (a TWO-buffer map, unlike scale's in-place
  // single buffer). The byte-exactness depends on the exp polynomial running on
  // real f32 lanes, so both must bind real f32 ABI buffers.
  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] row read for the silu)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml y[] silu output buffer)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // ANTI-BYPASS (I7): the strip_index MUST be the enclosing loop op's region
  // induction variable (region argument 0), so the emit provably addresses strip
  // i (input/output + strip_index), not the loop-invariant strip 0.
  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 1 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0) so the emit addresses input/output + "
              "strip_index, not the loop-invariant strip 0 (anti-bypass)";

  return mlir::success();
}

mlir::LogicalResult ElementwiseBinaryMapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind, the byte-exact combiner
  // selector 'binary_op', and the optional resource/scheduling strip-LMUL knob.
  // A forbidden local element_count/SEW/LMUL/policy attr or an unexpected name
  // fails closed (I7). The knob is named "strip_lmul" (not the with_vl/setvl
  // "lmul" spelling), exactly as the sibling scale map.
  auto isAllowedBinaryAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "binary_op" || name == "strip_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_binary_map keeps SEW/LMUL/policy on "
                "setvl/with_vl and rejects deleted local element_count metadata";
    if (!isAllowedBinaryAttr(attrName))
      return emitOpError()
             << "only accepts the bounded binary-map attributes 'kind', "
                "'binary_op', and 'strip_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_binary_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_binary_map\" for the "
              "bounded per-strip f32 two-input map brick";
  // The byte-exact combiner: "add" -> vfadd_vv, "mul" -> vfmul_vv. Fail-closed.
  if (getBinaryOp() != "add" && getBinaryOp() != "mul")
    return emitOpError()
           << "only accepts binary_op \"add\" (vfadd_vv) or \"mul\" (vfmul_vv); "
              "got \""
           << getBinaryOp() << "\"";
  if (std::optional<llvm::StringRef> stripLmul = getStripLmul()) {
    if (*stripLmul != "m1" && *stripLmul != "m2" && *stripLmul != "m4" &&
        *stripLmul != "m8")
      return emitOpError()
             << "only accepts strip_lmul \"m1\", \"m2\", \"m4\", or \"m8\"; got "
                "\""
             << *stripLmul << "\"";
  }

  // The TWO read-only inputs (const float *) + the written output (float *) --
  // add/mul read x[]/y[] and write z[] (a THREE-buffer binary map).
  RuntimeABIValueOp lhsBinding = getLhs().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp rhsBinding = getRhs().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!lhsBinding || lhsBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the lhs operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] input)";
  if (!rhsBinding || rhsBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the rhs operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml y[] input)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml z[] output buffer)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // ANTI-BYPASS (I7): the strip_index MUST be the enclosing loop op's region
  // induction variable (region argument 0).
  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 1 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0) so the emit addresses "
              "lhs/rhs/output + strip_index, not the loop-invariant strip 0 "
              "(anti-bypass)";

  return mlir::success();
}

mlir::LogicalResult ElementwiseCopyMapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind + the optional
  // resource/scheduling strip-LMUL knob. Fail-closed (I7).
  auto isAllowedCopyAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "strip_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_copy_map keeps SEW/LMUL/policy on "
                "setvl/with_vl and rejects deleted local element_count metadata";
    if (!isAllowedCopyAttr(attrName))
      return emitOpError()
             << "only accepts the bounded copy-map attributes 'kind' and "
                "'strip_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_copy_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_copy_map\" for the "
              "bounded per-strip f32 pass-through copy map brick";
  if (std::optional<llvm::StringRef> stripLmul = getStripLmul()) {
    if (*stripLmul != "m1" && *stripLmul != "m2" && *stripLmul != "m4" &&
        *stripLmul != "m8")
      return emitOpError()
             << "only accepts strip_lmul \"m1\", \"m2\", \"m4\", or \"m8\"; got "
                "\""
             << *stripLmul << "\"";
  }

  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] row copied)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml y[] copy destination)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 1 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0) so the emit addresses input/output + "
              "strip_index, not the loop-invariant strip 0 (anti-bypass)";

  return mlir::success();
}

mlir::LogicalResult ElementwiseGeluMapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind, plus the OPTIONAL
  // precision-tier selector `gelu_precision`. Gelu's reference body is a SCALAR
  // per-element loop (no vector strip), so there is NO resource/scheduling
  // strip_lmul knob. The precision selector is a bounded numeric-contract knob
  // (NOT a resource/scheduling knob): "f16lut" picks the same-precision-tier
  // GGML_GELU_FP16 seam (byte-exact to the as-shipped f16 lookup table), absent =
  // the exact-tanhf reference tier. Fail-closed (I7): only these two attrs, and
  // gelu_precision may only carry the bounded value "f16lut".
  auto isAllowedGeluAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "gelu_precision";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_gelu_map keeps SEW/LMUL/policy on "
                "setvl/with_vl and rejects deleted local element_count metadata";
    if (!isAllowedGeluAttr(attrName))
      return emitOpError()
             << "only accepts the bounded gelu-map attributes 'kind' / "
                "'gelu_precision'; unexpected attribute '"
             << attr.getName() << "'";
  }
  if (auto prec = op->getAttrOfType<mlir::StringAttr>("gelu_precision"))
    if (prec.getValue() != "f16lut")
      return emitOpError() << "gelu_precision only accepts the bounded value "
                              "\"f16lut\"; got '"
                           << prec.getValue() << "'";

  if (getKind() != "elementwise_gelu_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_gelu_map\" for the "
              "bounded per-element f32 tanh-gelu map brick";

  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] row read for the gelu)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml y[] gelu output buffer)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 1 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0) so the emit addresses input/output + "
              "strip_index, not the loop-invariant strip 0 (anti-bypass)";

  return mlir::success();
}

mlir::LogicalResult ElementwiseRmsNormReduceCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind + the optional
  // resource/scheduling NORMALIZE strip-LMUL knob. A forbidden local
  // element_count/SEW/LMUL/policy attr or an unexpected name fails closed (I7).
  // The knob is named "strip_lmul" (not the forbidden with_vl/setvl "lmul"
  // spelling), exactly as the sibling scale map. The strip knob governs only
  // the vectorized normalize tail; the Σx² reduction is always scalar-double.
  auto isAllowedRmsNormAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "strip_lmul";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_rms_norm_reduce_core keeps "
                "SEW/LMUL/policy on setvl/with_vl and rejects deleted local "
                "element_count metadata";
    if (!isAllowedRmsNormAttr(attrName))
      return emitOpError()
             << "only accepts the bounded rms_norm reduce-core attributes 'kind' "
                "and 'strip_lmul'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_rms_norm_reduce_core")
    return emitOpError()
           << "currently supports only kind "
              "\"elementwise_rms_norm_reduce_core\" for the bounded f32 rms_norm "
              "reduce-core brick";

  // The optional strip-LMUL is a bounded resource/scheduling fact: the NORMALIZE
  // strip loop (y[i] = x[i] * scale) anchors at m1/m2/m4/m8 (default m8). All are
  // byte-exact (every lane is multiplied by the same scalar scale; the runtime
  // vsetvl_e32m<L>(n-i) re-strips correctly for any VLEN). The reduction is
  // scalar-double regardless of this knob. Any other spelling is rejected (I7).
  if (std::optional<llvm::StringRef> stripLmul = getStripLmul()) {
    if (*stripLmul != "m1" && *stripLmul != "m2" && *stripLmul != "m4" &&
        *stripLmul != "m8")
      return emitOpError()
             << "only accepts strip_lmul \"m1\", \"m2\", \"m4\", or \"m8\" (the "
                "bounded byte-exact f32-strip resource anchors for the rms_norm "
                "normalize tail); got \""
             << *stripLmul << "\"";
  }

  // The input is read-only (const float *), the output is written (float *), eps
  // binds a runtime f32. ggml's rms_norm reads x and writes y (the non-fused,
  // no-weight path); the byte-exactness depends on x[i]*x[i] being a true f32
  // product widened to double, so the input must be a real f32 buffer.
  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp epsBinding = getEps().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] row read for the Σx² reduction and "
              "the normalize)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml y[] normalized output buffer)";
  if (!epsBinding || epsBinding.getCType() != "float")
    return emitOpError()
           << "requires the eps operand to bind a runtime ABI value of C type "
              "'float' (the ggml runtime eps)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // ANTI-BYPASS (I7): the strip_index MUST be the enclosing loop op's region
  // induction variable (region argument 0), and `acc` MUST be the loop-carried
  // accumulator (region argument 1), so the emit provably folds the carried
  // value at strip i, not a fresh zero at the loop-invariant strip 0.
  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  if (parent.getReduceMapModel() != "reduce")
    return emitOpError()
           << "requires the enclosing loop op to carry reduce_map_model "
              "\"reduce\" (the loop-carried accumulator model)";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 2 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0), not the loop-invariant strip 0 "
              "(anti-bypass)";
  if (getAcc() != parentBlock.getArgument(1))
    return emitOpError()
           << "requires acc to be the enclosing loop's loop-carried accumulator "
              "(region argument 1), so the emit folds the carried Σx² value";

  // OPTIONAL fused rms_norm->mul epilogue region: 0 blocks (plain rms_norm, the
  // unfused byte-identical path) or 1 block carrying exactly ONE entry argument
  // -- the per-strip normalized vector `vy` at this brick's NORMALIZE strip LMUL
  // -- plus exactly ONE weft_rvv.elementwise_mul_map consumer brick. The chain
  // block arg is a declaration the reduce-body emitter binds to the C `vy`
  // variable (the per-strip value is not a real SSA value at the typed-body
  // layer). The mul_map brick's own verifier pins the chain/strip_index/output
  // anti-bypass ties.
  mlir::Region &epilogue = getEpilogue();
  if (!epilogue.empty()) {
    if (!llvm::hasSingleElement(epilogue))
      return emitOpError()
             << "the optional fused rms_norm->mul epilogue region must hold at "
                "most one block";
    mlir::Block &epiBlock = epilogue.front();
    if (epiBlock.getNumArguments() != 1)
      return emitOpError()
             << "the fused epilogue region must carry exactly one block argument: "
                "the per-strip normalized vector chain (the producer's vy)";
    llvm::StringRef stripLmul = getStripLmul().value_or("m8");
    if (!isGenericRVVVectorType(epiBlock.getArgument(0).getType(),
                                getRVVSEW32Bits(), stripLmul))
      return emitOpError()
             << "the fused epilogue chain block argument must be an f32 RVV vector "
                "at the normalize strip LMUL \""
             << stripLmul << "\" (the register-kept vy)";
    if (epiBlock.getOperations().size() != 1 ||
        epiBlock.getOps<ElementwiseMulMapOp>().empty())
      return emitOpError()
             << "the fused epilogue region must carry exactly one "
                "weft_rvv.elementwise_mul_map consumer brick";
  }

  return mlir::success();
}

mlir::LogicalResult ElementwiseMulMapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind. The mul epilogue runs at
  // the producer's normalize strip LMUL (it consumes the register-kept vy at its
  // native width), so there is NO independent strip_lmul knob this brick -- the
  // ONLY allowed attr is "kind". A forbidden local element_count/SEW/LMUL/policy
  // attr or an unexpected name fails closed (I7).
  auto isAllowedMulAttr = [](llvm::StringRef name) { return name == "kind"; };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_mul_map keeps SEW/LMUL/policy on "
                "setvl/with_vl and rejects deleted local element_count metadata";
    if (!isAllowedMulAttr(attrName))
      return emitOpError()
             << "only accepts the bounded mul-map attribute 'kind'; unexpected "
                "attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_mul_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_mul_map\" for the "
              "bounded per-strip f32 mul epilogue brick";

  // The weight is read-only (const float *), the output is written (float *) --
  // the mul reads w[] (the learned weight row) and writes z[] (the fused result).
  RuntimeABIValueOp weightBinding =
      getWeight().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the weight operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml mul weight row w[])";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml z[] fused rms_norm->mul output buffer)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // ANTI-BYPASS (chain): chain MUST be the enclosing $epilogue region's block
  // argument 0 (the producer's per-strip vy), so the emit multiplies the
  // register-kept normalized vector, not a memory reload. The producer is the
  // reduce core that owns this epilogue region.
  auto producer = op->getParentOfType<ElementwiseRmsNormReduceCoreOp>();
  mlir::Region *epilogue = op->getParentRegion();
  if (!producer || !epilogue || epilogue != &producer.getEpilogue())
    return emitOpError()
           << "must be carried inside the $epilogue region of a "
              "weft_rvv.elementwise_rms_norm_reduce_core producer";
  mlir::Block &epiBlock = epilogue->front();
  if (epiBlock.getNumArguments() < 1 || getChain() != epiBlock.getArgument(0))
    return emitOpError()
           << "requires chain to be the enclosing epilogue region's per-strip "
              "normalized vector (block argument 0), so the emit multiplies the "
              "register-kept vy, not a memory reload (anti-bypass chain tie)";

  // The output MUST be the producer reduce core's output buffer: a single fused
  // destination z[], so the norm[] intermediate never exists.
  if (getOutput() != producer.getOutput())
    return emitOpError()
           << "requires output to be the producer reduce core's output buffer "
              "(the single fused rms_norm->mul destination z[])";

  // ANTI-BYPASS (strip_index): strip_index MUST be the enclosing loop body's
  // induction variable (region argument 0), so the emit addresses weight/output
  // + strip_index, not the loop-invariant strip 0.
  auto loop = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!loop)
    return emitOpError()
           << "must be nested (via the reduce core's epilogue) under a "
              "weft_rvv.typed_elementwise_loop_body";
  mlir::Block &loopBlock = loop.getBody().front();
  if (loopBlock.getNumArguments() < 1 ||
      getStripIndex() != loopBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction variable "
              "(region argument 0), not the loop-invariant strip 0 (anti-bypass)";

  // OPTIONAL [FMT-PROP] fused-activation-quantize epilogue region: 0 blocks (the
  // plain fused rms_norm->mul that stores f32 z[]) or 1 block carrying exactly ONE
  // entry argument -- the per-block WEIGHTED vector `vz` at the producer normalize
  // strip LMUL -- plus exactly ONE weft_rvv.elementwise_quantize_q8_0_map consumer
  // brick. When present, the emit runs the per-block amax/scale/narrow q8_0 body
  // on the register-kept vz and stores block_q8_0: the f32 z[] intermediate is
  // NEVER stored and the downstream independent quantize_row pass is elided. The
  // quantize brick's own verifier pins the chain/strip_index/output anti-bypass
  // ties.
  mlir::Region &quantEpi = getQuantEpilogue();
  if (!quantEpi.empty()) {
    if (!llvm::hasSingleElement(quantEpi))
      return emitOpError()
             << "the optional fused quant epilogue region must hold at most one "
                "block";
    mlir::Block &qBlock = quantEpi.front();
    if (qBlock.getNumArguments() != 1)
      return emitOpError()
             << "the fused quant epilogue region must carry exactly one block "
                "argument: the per-block weighted vector chain (the register-kept "
                "vz)";
    // The ggml per-block amax/scale/narrow q8_0 body rides the e32m8 QK8_0 strip
    // (vl=32), so the register-kept vz must be an f32 m8 vector -- the producer
    // normalize strip LMUL must be m8 for this fused-quant path.
    llvm::StringRef stripLmul = producer.getStripLmul().value_or("m8");
    if (stripLmul != "m8")
      return emitOpError()
             << "the fused quant epilogue requires the producer normalize strip "
                "LMUL to be \"m8\" (the ggml QK8_0 e32m8 quantize block); got \""
             << stripLmul << "\"";
    if (!isGenericRVVVectorType(qBlock.getArgument(0).getType(),
                                getRVVSEW32Bits(), "m8"))
      return emitOpError()
             << "the fused quant epilogue chain block argument must be an f32 RVV "
                "vector at \"m8\" (the register-kept weighted vz block)";
    if (qBlock.getOperations().size() != 1 ||
        qBlock.getOps<ElementwiseQuantizeQ80MapOp>().empty())
      return emitOpError()
             << "the fused quant epilogue region must carry exactly one "
                "weft_rvv.elementwise_quantize_q8_0_map consumer brick";
  }

  return mlir::success();
}

mlir::LogicalResult ElementwiseQuantizeQ80MapOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind + the block_q8_0 AoS
  // format facts (qk / block_stride / scale/quant byte offsets), IDENTICAL to
  // weft_rvv.quantize_row_q8_0's mirror attrs. There is NO resource/scheduling
  // LMUL knob this cut -- the quantize block rides ggml's e32m8 QK8_0 strip. A
  // forbidden local element_count/SEW/LMUL/policy attr or an unexpected name fails
  // closed (I7).
  auto isAllowedQuantizeAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "block_stride" ||
           name == "scale_byte_offset" || name == "quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_quantize_q8_0_map keeps SEW/LMUL/policy "
                "on setvl/with_vl and rejects deleted local element_count "
                "metadata";
    if (!isAllowedQuantizeAttr(attrName))
      return emitOpError()
             << "only accepts the bounded f32->q8_0 quantize-map attributes "
                "'kind', 'qk', 'block_stride', 'scale_byte_offset', and "
                "'quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_quantize_q8_0_map")
    return emitOpError()
           << "currently supports only kind \"elementwise_quantize_q8_0_map\" for "
              "the bounded per-block f32->block_q8_0 quantize epilogue brick";

  // The block-format facts are the ggml block_q8_0 layout (ggml-common.h + QK8_0 =
  // 32): a 32-element block, AoS stride 34 (the fp16 d at byte 0, the 32 int8 qs
  // at byte 2). They are bounded mirror facts IDENTICAL to the standalone
  // quantizer; any other layout is rejected fail-closed (I7).
  if (getQk() != 32)
    return emitOpError()
           << "requires qk = 32 (the ggml QK8_0 block length); got " << getQk();
  if (getBlockStride() != 34)
    return emitOpError()
           << "requires block_stride = 34 (the ggml block_q8_0 AoS stride: 2 fp16 "
              "d bytes + 32 int8 qs bytes); got "
           << getBlockStride();
  if (getScaleByteOffset() != 0)
    return emitOpError()
           << "requires scale_byte_offset = 0 (the ggml block_q8_0 fp16 d at byte "
              "0); got "
           << getScaleByteOffset();
  if (getQuantByteOffset() != 2)
    return emitOpError()
           << "requires quant_byte_offset = 2 (the ggml block_q8_0 int8 qs after "
              "the 2-byte fp16 d); got "
           << getQuantByteOffset();

  // The output binds the block_q8_0 AoS BYTE buffer (uint8_t *) the fp16 d + int8
  // qs stores write into -- the SEPARATE fused-quant destination (the f32 z[]
  // intermediate the producer would have written is elided, never materialized).
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!outputBinding || outputBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'uint8_t *' (the ggml block_q8_0 AoS byte buffer the fp16 d + int8 "
              "qs stores write)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index value "
              "(ggml's k, n % 32 == 0) feeding the enclosing setvl";

  // ANTI-BYPASS (chain): chain MUST be the enclosing $quant_epilogue region's
  // block argument 0 (the producer mul's per-block weighted vz), so the emit
  // quantizes the register-kept weighted vector, not a memory reload. The producer
  // is the mul_map that owns this quant epilogue region.
  auto mul = op->getParentOfType<ElementwiseMulMapOp>();
  mlir::Region *quantEpi = op->getParentRegion();
  if (!mul || !quantEpi || quantEpi != &mul.getQuantEpilogue())
    return emitOpError()
           << "must be carried inside the $quant_epilogue region of a "
              "weft_rvv.elementwise_mul_map producer";
  mlir::Block &quantBlock = quantEpi->front();
  if (quantBlock.getNumArguments() < 1 ||
      getChain() != quantBlock.getArgument(0))
    return emitOpError()
           << "requires chain to be the enclosing quant epilogue region's "
              "per-block weighted vector (block argument 0), so the emit quantizes "
              "the register-kept vz, not a memory reload (anti-bypass chain tie)";

  // ANTI-BYPASS (strip_index): strip_index MUST be the enclosing loop body's
  // induction variable (region argument 0), so the emit addresses the AoS output
  // block cursor at block ib, not the loop-invariant block 0.
  auto loop = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!loop)
    return emitOpError()
           << "must be nested (via the mul_map's quant epilogue) under a "
              "weft_rvv.typed_elementwise_loop_body";
  mlir::Block &loopBlock = loop.getBody().front();
  if (loopBlock.getNumArguments() < 1 ||
      getStripIndex() != loopBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction variable "
              "(region argument 0), not the loop-invariant block 0 (anti-bypass)";

  return mlir::success();
}

mlir::LogicalResult ElementwiseSoftMaxReduceCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind. soft_max is m2-pinned
  // (the exp polynomial's mask/reinterpret types are m2-tied) and the reduce is
  // f64m1 (the vfwredusum destination), so there is NO resource/scheduling
  // strip_lmul knob this reduce -- the ONLY allowed attr is "kind" (matching
  // silu's precedent). A forbidden local element_count/SEW/LMUL/policy attr or an
  // unexpected name fails closed (I7).
  auto isAllowedSoftMaxAttr = [](llvm::StringRef name) { return name == "kind"; };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_soft_max_reduce_core keeps SEW/LMUL/"
                "policy on setvl/with_vl and rejects deleted local element_count "
                "metadata";
    if (!isAllowedSoftMaxAttr(attrName))
      return emitOpError()
             << "only accepts the bounded soft_max reduce-core attribute 'kind'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_soft_max_reduce_core")
    return emitOpError()
           << "currently supports only kind "
              "\"elementwise_soft_max_reduce_core\" for the bounded f32 soft_max "
              "exp-sum-reduce core brick";

  // The output is written (float *), the input is read-only (const float *), max
  // binds a runtime f32. ggml's bare ggml_vec_soft_max_f32 writes y[i]=e^{x[i]-max}
  // and reads x[]; the byte-exactness depends on the exp polynomial running on
  // real f32 lanes and the f64 widening reduce, so x must be a real f32 buffer.
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp maxBinding = getMax().getDefiningOp<RuntimeABIValueOp>();
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml y[] = e^{x-max} output buffer)";
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] row read for the soft_max)";
  if (!maxBinding || maxBinding.getCType() != "float")
    return emitOpError()
           << "requires the max operand to bind a runtime ABI value of C type "
              "'float' (the ggml runtime row max subtracted before exp)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // The loop-carried accumulator (in and out) is the f64m1 WIDENING accumulator
  // (ggml's vfloat64m1_t vsum, the vfwredusum_vs_f32m2_f64m1 destination), NOT a
  // scalar double: matching THAT exact fold is the byte-exactness crux for the
  // returned sum.
  if (!isGenericRVVVectorF64M1(getAcc().getType()))
    return emitOpError()
           << "requires the acc operand to have type !weft_rvv.vector<f64, "
              "\"m1\"> (the ggml vfloat64m1_t vsum widening accumulator)";
  if (!isGenericRVVVectorF64M1(getAccNext().getType()))
    return emitOpError()
           << "requires the acc_next result to have type !weft_rvv.vector<f64, "
              "\"m1\"> (the updated soft_max widening accumulator)";

  // ANTI-BYPASS (I7): the strip_index MUST be the enclosing loop op's region
  // induction variable (region argument 0), and `acc` MUST be the loop-carried
  // accumulator (region argument 1), so the emit provably folds the carried vsum
  // at strip i, not a fresh zero at the loop-invariant strip 0.
  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  if (parent.getReduceMapModel() != "reduce")
    return emitOpError()
           << "requires the enclosing loop op to carry reduce_map_model "
              "\"reduce\" (the loop-carried accumulator model)";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 2 ||
      getStripIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires strip_index to be the enclosing loop's induction "
              "variable (region argument 0), not the loop-invariant strip 0 "
              "(anti-bypass)";
  if (getAcc() != parentBlock.getArgument(1))
    return emitOpError()
           << "requires acc to be the enclosing loop's loop-carried accumulator "
              "(region argument 1), so the emit folds the carried Σe^x vsum";

  return mlir::success();
}

mlir::LogicalResult ElementwiseRopeRotateCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded mirror attrs only (I4): the operation kind. rope is a scalar per-pair
  // loop (cos/sin are scalar libm, one call per pair), so there is NO
  // resource/scheduling strip_lmul knob this rotate -- the ONLY allowed attr is
  // "kind" (matching silu's / soft_max's no-knob precedent). A forbidden local
  // element_count/SEW/LMUL/policy attr or an unexpected name fails closed (I7).
  auto isAllowedRopeAttr = [](llvm::StringRef name) { return name == "kind"; };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.elementwise_rope_rotate_core keeps SEW/LMUL/policy "
                "on setvl/with_vl and rejects deleted local element_count "
                "metadata";
    if (!isAllowedRopeAttr(attrName))
      return emitOpError()
             << "only accepts the bounded rope rotate-core attribute 'kind'; "
                "unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "elementwise_rope_rotate_core")
    return emitOpError()
           << "currently supports only kind \"elementwise_rope_rotate_core\" for "
              "the bounded f32 NORMAL rope rotate-core brick";

  // The input is read-only (const float *), the output is written (float *),
  // theta_base / theta_scale bind runtime f32 values. ggml's rope reads x[] (one
  // head row) and writes y[]; the byte-exactness of the rotation depends on the
  // f32 inputs being real f32 buffers, so input/output must bind real f32
  // pointers. theta_base (pos as f32) / theta_scale (powf(freq_base, -2/n_dims))
  // are PRECOMPUTED runtime f32 inputs, so the kernel makes no powf call.
  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp thetaBaseBinding =
      getThetaBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp thetaScaleBinding =
      getThetaScale().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] head row read for the rotation)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml y[] rotated output buffer)";
  if (!thetaBaseBinding || thetaBaseBinding.getCType() != "float")
    return emitOpError()
           << "requires the theta_base operand to bind a runtime ABI value of C "
              "type 'float' (the ggml position pos as f32, the angle recurrence "
              "seed)";
  if (!thetaScaleBinding || thetaScaleBinding.getCType() != "float")
    return emitOpError()
           << "requires the theta_scale operand to bind a runtime ABI value of C "
              "type 'float' (the ggml powf(freq_base, -2/n_dims) recurrence "
              "ratio)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value (ggml's ne0, n % 2 == 0) feeding the enclosing setvl";

  // ANTI-BYPASS (I7): the pair_index MUST be the enclosing loop op's region
  // induction variable (region argument 0), and `theta` MUST be the loop-carried
  // recurrence value (region argument 1), so the emit provably steps the carried
  // angle at pair p, not a fresh seed at the loop-invariant pair 0.
  auto parent = op->getParentOfType<TypedElementwiseLoopBodyOp>();
  if (!parent)
    return emitOpError()
           << "must be carried inside a weft_rvv.typed_elementwise_loop_body "
              "region";
  if (parent.getReduceMapModel() != "rotate")
    return emitOpError()
           << "requires the enclosing loop op to carry reduce_map_model "
              "\"rotate\" (the per-pair loop-carried f32 recurrence model)";
  mlir::Block &parentBlock = parent.getBody().front();
  if (parentBlock.getNumArguments() < 2 ||
      getPairIndex() != parentBlock.getArgument(0))
    return emitOpError()
           << "requires pair_index to be the enclosing loop's induction "
              "variable (region argument 0), not the loop-invariant pair 0 "
              "(anti-bypass)";
  if (getTheta() != parentBlock.getArgument(1))
    return emitOpError()
           << "requires theta to be the enclosing loop's loop-carried f32 "
              "recurrence (region argument 1), so the emit steps the carried "
              "theta";

  return mlir::success();
}

mlir::LogicalResult GgmlForwardElementwiseOp::verify() {
  // The abstract SOURCE op for the 5 CONSTRUCTED forward-elementwise operators.
  // Fail-closed (I7): the bounded `elementwise_model` MUST be one of the 5-op
  // allowlist, the abi_operands arity MUST match the model's ABI, the runtime
  // element count (LAST operand) MUST be the `index` n feeding the enclosing setvl,
  // and the leading buffer operands MUST bind runtime ABI values (the front-door
  // construction threads them verbatim into the per-op CORE brick, whose OWN
  // verifier then pins the exact C-types after construction). The op carries NO
  // dataflow SEW/LMUL/policy knob (those live on setvl/with_vl); the ONLY optional
  // knob is `strip_lmul` (the scale/rms_norm normalize strip anchor).
  llvm::StringRef model = getElementwiseModel();
  // model -> required abi_operands arity (n is always the last operand). The MAP
  // family now includes the four forward SUPPORT ops (add/mul binary, cpy/gelu
  // unary), each constructed into the SAME typed_elementwise_loop_body region as
  // scale/silu (a per-strip elementwise_binary_map / elementwise_copy_map /
  // elementwise_gelu_map core brick).
  unsigned wantArity = 0;
  if (model == "scale" || model == "silu" || model == "cpy" || model == "gelu")
    wantArity = 3; // (buf0, buf1, n)
  else if (model == "rms_norm" || model == "soft_max" || model == "add" ||
           model == "mul")
    wantArity = 4; // rms_norm/soft_max: (x, y, {eps|max}, n); add/mul: (x, y, z, n)
  else if (model == "rope")
    wantArity = 5; // (x, y, theta_base, theta_scale, n)
  else
    return emitOpError()
           << "currently supports only elementwise_model in "
              "{\"scale\",\"silu\",\"rms_norm\",\"soft_max\",\"rope\",\"add\","
              "\"mul\",\"cpy\",\"gelu\"}; got \""
           << model << "\"";

  mlir::OperandRange operands = getAbiOperands();
  if (operands.size() != wantArity)
    return emitOpError() << "elementwise_model \"" << model << "\" requires "
                         << wantArity << " abi_operands (n last), got "
                         << operands.size();

  // The LAST operand is the runtime element count n (the index feeding setvl).
  if (!llvm::isa<mlir::IndexType>(operands.back().getType()))
    return emitOpError()
           << "requires the last abi_operand to be the runtime n `index` value "
              "(the runtime element count feeding the enclosing setvl)";

  // Every leading operand (all but the trailing n) binds a runtime ABI value (the
  // in/out f32 buffers + the scalar broadcasts eps/max/v/theta); the CORE brick
  // verifier pins their exact C-types post-construction. The BINARY support ops
  // (add/mul) thus require all THREE leading buffers (lhs/rhs/output) to bind ABI
  // values, not just the two the map family carries.
  for (unsigned i = 0; i + 1 < operands.size(); ++i)
    if (!operands[i].getDefiningOp<RuntimeABIValueOp>())
      return emitOpError() << "requires abi_operand #" << i
                           << " to bind a runtime ABI value (the in/out f32 "
                              "buffer or scalar broadcast)";

  return mlir::success();
}

// NOTE: verifyForwardElementwiseF32Common + the four forward-elementwise f32 support-op
// verifiers (GgmlVecAddF32Op / GgmlVecMulF32Op / GgmlVecCpyF32Op / GgmlGeluF32Op::verify)
// were RETIRED at the support flip (dispatch-wired -> constructed, C_construct 73->77):
// add/mul/cpy/gelu are now CONSTRUCTED through the abstract GgmlForwardElementwiseOp
// source op + the typed_elementwise_loop_body region carrying the per-op
// elementwise_binary_map / elementwise_copy_map / elementwise_gelu_map core brick, whose
// own verifiers (above) are the live bounded-surface gates.

mlir::LogicalResult GgmlDequantizeRowOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded `format` mirror attr (I4): no forbidden
  // dataflow SEW/LMUL/policy/element_count knob, and no unexpected name. The
  // per-format AoS block facts are constructed later by the family-local formula;
  // this source verifier does not replay its format table.
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.dequantize_row keeps SEW/LMUL/policy on "
                "setvl/with_vl and runtime k/AVL/VL in the surrounding "
                "control-plane IR";
    if (attrName != "format")
      return emitOpError()
             << "only accepts the bounded 'format' attribute; unexpected "
                "attribute '"
             << attr.getName() << "'";
  }

  if (getFormat().empty())
    return emitOpError()
           << "requires a non-empty source format; the pre-emission formula "
              "construction cut decides support and rejects unknown formats";

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one read-only quantized-weight byte pointer, one f32 "
              "output pointer, one runtime element-count, one !weft_rvv.vl "
              "operand, and one f32 LMUL m1 result";

  // ggml's dequantize_row_<format> reads the AoS block buffer (const block_qX *,
  // taken as a const uint8_t * byte cursor) and writes the f32 y[] row.
  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const uint8_t *' (the ggml block_qX AoS byte buffer decoded to "
              "f32)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml y[] dequantized row)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError() << "requires the element-count operand to be the "
                            "runtime k index value feeding the enclosing setvl";

  if (!isGenericRVVVectorF32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<f32, \"m1\"> "
              "for the dequantize_row store boundary";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have !weft_rvv.vl "
                            "type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the dequantize_row support op";
  return mlir::success();
}

mlir::LogicalResult TypedDequantizeRowLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): kind, the ggml ABI block
  // facts (qk / weight_block_stride), and the decode_model leaf key. A forbidden
  // local element_count/SEW/LMUL/policy attr or an unexpected name is rejected
  // fail-closed (I7); SEW/LMUL/policy live on setvl/with_vl, runtime k on the ABI.
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "weight_block_stride" ||
           name == "decode_model";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.typed_dequantize_row_loop_body keeps SEW/LMUL/policy "
                "on setvl/with_vl and runtime k/AVL/VL in the surrounding "
                "control-plane IR";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded {kind, qk, weight_block_stride, "
                "decode_model} attributes; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "typed_dequantize_row_loop_body")
    return emitOpError()
           << "currently supports only kind "
              "\"typed_dequantize_row_loop_body\" for the bounded streaming "
              "dequantize_row nb loop surface";
  if (getDecodeModel().empty())
    return emitOpError()
           << "requires non-empty source provenance in decode_model; execution "
              "is selected by the typed mechanism/plan on the decode core";

  // qk / weight_block_stride are positive ggml ABI byte counts the per-block
  // address arithmetic depends on. Read the SIGNED attr view so a NEGATIVE spelling
  // fail-CLOSES the `<= 0` guard (a uint64_t accessor would zero-extend and
  // fail-OPEN); mirrors the TypedFlatBlockDotLoopBodyOp positivity gate (I7).
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0 (the QK block element count); got "
                         << getQkAttr().getInt();
  if (getWeightBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_block_stride > 0 (the AoS weight block stride); "
              "got "
           << getWeightBlockStrideAttr().getInt();

  if (op->getNumOperands() != 3 || op->getNumResults() != 0)
    return emitOpError()
           << "requires one weight base pointer, one f32 output pointer, and one "
              "runtime element-count ABI operand, and no results (the streaming "
              "store is the sink)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of C "
              "type 'const uint8_t *' (the ggml block_qX AoS byte buffer)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml y[] dequantized row)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index value "
              "feeding the enclosing setvl";

  // Region structure: exactly ONE entry argument -- the block_index induction
  // variable (index). Unlike the block-dot loop ops there is NO loop-carried
  // accumulator (the decode STORES to memory), so the region is terminated by the
  // VOID weft_rvv.typed_dequantize_row_loop_yield.
  mlir::Block &block = getBody().front();
  if (block.getNumArguments() != 1)
    return emitOpError()
           << "requires the region to carry exactly one entry argument: the "
              "block_index induction variable (streaming decode has no "
              "loop-carried accumulator)";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (block_index) to be index-typed "
              "(the nb block induction variable)";

  TypedDequantizeRowLoopYieldOp yield =
      block.empty()
          ? TypedDequantizeRowLoopYieldOp()
          : llvm::dyn_cast<TypedDequantizeRowLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_dequantize_row_loop_yield (the VOID streaming-store "
              "sink)";

  return mlir::success();
}

mlir::LogicalResult DequantizeRowDecodeCoreOp::verify() {
  mlir::Operation *op = getOperation();

  auto parentLoop = llvm::dyn_cast_or_null<TypedDequantizeRowLoopBodyOp>(
      op->getParentOp());
  if (!parentLoop)
    return emitOpError()
           << "must be directly nested in "
              "weft_rvv.typed_dequantize_row_loop_body";
  if (parentLoop.getDecodeModel() != getDecodeModel())
    return emitOpError()
           << "requires parent/core decode_model construction coherence; parent "
              "carries '"
           << parentLoop.getDecodeModel() << "' while the core carries '"
           << getDecodeModel() << "'";

  // Bounded mirror attrs (I4): the decode_model leaf key + the ggml ABI block
  // layout facts. A forbidden dataflow attr or an unexpected name fails closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "decode_model" || name == "qk" ||
           name == "weight_block_stride" || name == "scale_byte_offset" ||
           name == "quant_byte_offset" || name == "dequant_mechanism" ||
           name == "codebook_scale_model" ||
           name == "kquant_scale_model" || name == "grid_decode_leaf" ||
           name == "ternary_decode_leaf" ||
           name == "dequant_load_lmul" ||
           name == "dequant_strip_lanes" ||
           name == "kquant_has_min" ||
           name == "kquant_min_byte_offset" ||
           name == "kquant_sub_scale_byte_offset" ||
           name == "kquant_has_high_bit_plane" ||
           name == "kquant_high_bit_byte_offset" ||
           name == "codebook_gather_table" ||
           name == "codebook_gather_entries" ||
           name == "codebook_entry_lanes" ||
           name == "carrier_kind" || name == "nibble_bias" ||
           name == "min_byte_offset" || name == "qh_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.dequantize_row_decode_core keeps SEW/LMUL/policy on "
                "setvl/with_vl";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded {decode_model, qk, weight_block_stride, "
                "scale_byte_offset, quant_byte_offset, dequant_mechanism, "
                "codebook_scale_model, kquant_scale_model, grid_decode_leaf, "
                "ternary_decode_leaf, dequant_{load_lmul,strip_lanes}, "
                "kquant_{has_min,min_byte_offset,sub_scale_byte_offset,"
                "has_high_bit_plane,high_bit_byte_offset}, "
                "codebook_gather_{table,entries}, "
                "codebook_entry_lanes, "
                "carrier_kind, nibble_bias, min_byte_offset, qh_byte_offset} "
                "attributes; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getDecodeModel().empty())
    return emitOpError()
           << "requires non-empty decode_model provenance; typed mechanism and "
              "selected plan fields, not provenance, drive emission";
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0; got " << getQkAttr().getInt();
  if (getWeightBlockStrideAttr().getInt() <= 0)
    return emitOpError() << "requires weight_block_stride > 0; got "
                         << getWeightBlockStrideAttr().getInt();
  if (getScaleByteOffsetAttr().getInt() < 0)
    return emitOpError() << "requires scale_byte_offset >= 0; got "
                         << getScaleByteOffsetAttr().getInt();
  if (getQuantByteOffsetAttr().getInt() < 0)
    return emitOpError() << "requires quant_byte_offset >= 0; got "
                         << getQuantByteOffsetAttr().getInt();
  // The OPTIONAL codebook grid ENTRY byte-width descriptor (g-axis geometry): when
  // present it must name a positive lane count.
  if (mlir::IntegerAttr entryLanes = getCodebookEntryLanesAttr())
    if (entryLanes.getInt() <= 0)
      return emitOpError() << "requires codebook_entry_lanes > 0 when present; got "
                           << entryLanes.getInt();
  // Phase-1 nibble-family descriptor: the OPTIONAL min / qh byte offsets are
  // non-negative AoS byte offsets (their PRESENCE is the hasMin / hasQh gate); the
  // pre-scale bias is a non-negative subtractive constant. Read the SIGNED attr view
  // so a NEGATIVE spelling fail-CLOSES (a uint accessor would zero-extend, fail-OPEN).
  if (mlir::IntegerAttr minOff = getMinByteOffsetAttr())
    if (minOff.getInt() < 0)
      return emitOpError() << "requires min_byte_offset >= 0 when present; got "
                           << minOff.getInt();
  if (mlir::IntegerAttr qhOff = getQhByteOffsetAttr())
    if (qhOff.getInt() < 0)
      return emitOpError() << "requires qh_byte_offset >= 0 when present; got "
                           << qhOff.getInt();
  if (mlir::IntegerAttr bias = getNibbleBiasAttr())
    if (bias.getInt() < 0)
      return emitOpError() << "requires nibble_bias >= 0 when present; got "
                           << bias.getInt();
  // The verifier checks only the typed construction's bounded shape. It never
  // classifies from decode_model and never replays a formula: source provenance
  // cannot regain compute authority after construction.
  mlir::StringAttr mechanismAttr =
      op->getAttrOfType<mlir::StringAttr>("dequant_mechanism");
  if (!mechanismAttr)
    return emitOpError()
           << "requires construction-owned dequant_mechanism; decode_model is "
              "provenance only";
  llvm::StringRef mechanism = mechanismAttr.getValue();
  bool isInt8 = mechanism == "int8-scale";
  bool isNibble = mechanism == "nibble-decode";
  bool isBinary = mechanism == "binary-sign";
  bool isKQuant = mechanism == "kquant-scale-min";
  bool isCodebook = mechanism == "codebook-gather";
  bool isGrid = mechanism == "grid-lookup";
  bool isTernary = mechanism == "ternary-decode";
  if (!isInt8 && !isNibble && !isBinary && !isKQuant && !isCodebook &&
      !isGrid && !isTernary)
    return emitOpError() << "requires dequant_mechanism in {int8-scale, "
                            "nibble-decode, binary-sign, kquant-scale-min, "
                            "codebook-gather, grid-lookup, ternary-decode}; got '"
                         << mechanism << "'";

  mlir::StringAttr carrier =
      op->getAttrOfType<mlir::StringAttr>("carrier_kind");
  mlir::IntegerAttr nibbleBias =
      op->getAttrOfType<mlir::IntegerAttr>("nibble_bias");
  mlir::IntegerAttr minByteOffset =
      op->getAttrOfType<mlir::IntegerAttr>("min_byte_offset");
  mlir::IntegerAttr qhByteOffset =
      op->getAttrOfType<mlir::IntegerAttr>("qh_byte_offset");
  mlir::StringAttr codebookScale =
      op->getAttrOfType<mlir::StringAttr>("codebook_scale_model");
  mlir::StringAttr kquantScale =
      op->getAttrOfType<mlir::StringAttr>("kquant_scale_model");
  mlir::StringAttr gridLeafAttr =
      op->getAttrOfType<mlir::StringAttr>("grid_decode_leaf");
  mlir::StringAttr ternaryLeafAttr =
      op->getAttrOfType<mlir::StringAttr>("ternary_decode_leaf");
  mlir::IntegerAttr entryLanes =
      op->getAttrOfType<mlir::IntegerAttr>("codebook_entry_lanes");

  std::optional<::weft::CodebookScaleModel> parsedCodebook =
      codebookScale ? ::weft::parseCodebookScaleModel(codebookScale.getValue())
                    : std::nullopt;
  std::optional<::weft::KQuantScaleModel> parsedKQuant =
      kquantScale ? ::weft::parseKQuantScaleModel(kquantScale.getValue())
                  : std::nullopt;
  std::optional<::weft::GridDecodeLeaf> parsedGrid =
      gridLeafAttr ? ::weft::parseGridDecodeLeaf(gridLeafAttr.getValue())
                   : std::nullopt;
  std::optional<::weft::TernaryDecodeLeaf> parsedTernary =
      ternaryLeafAttr
          ? ::weft::parseTernaryDecodeLeaf(ternaryLeafAttr.getValue())
          : std::nullopt;
  if (codebookScale && !parsedCodebook)
    return emitOpError() << "unknown codebook_scale_model '"
                         << codebookScale.getValue() << "'";
  if (kquantScale && !parsedKQuant)
    return emitOpError() << "unknown kquant_scale_model '"
                         << kquantScale.getValue() << "'";
  if (gridLeafAttr && !parsedGrid)
    return emitOpError() << "unknown grid_decode_leaf '"
                         << gridLeafAttr.getValue() << "'";
  if (ternaryLeafAttr && !parsedTernary)
    return emitOpError() << "unknown ternary_decode_leaf '"
                         << ternaryLeafAttr.getValue() << "'";
  if (carrier && carrier.getValue() != "bare_int8" &&
      carrier.getValue() != "nibble4")
    return emitOpError() << "requires carrier_kind in {bare_int8,nibble4}; got '"
                         << carrier.getValue() << "'";

  auto rejectForeignGeometry = [&](bool allowCarrier, bool allowCodebook,
                                   bool allowKQuant, bool allowGrid,
                                   bool allowTernary, bool allowEntry)
      -> mlir::LogicalResult {
    if (!allowCarrier &&
        (carrier || nibbleBias || minByteOffset || qhByteOffset))
      return emitOpError()
             << "mechanism '" << mechanism
             << "' must not carry nibble/int8 carrier geometry";
    if (!allowCodebook && codebookScale)
      return emitOpError() << "mechanism '" << mechanism
                           << "' must not carry codebook_scale_model";
    if (!allowKQuant && kquantScale)
      return emitOpError() << "mechanism '" << mechanism
                           << "' must not carry kquant_scale_model";
    if (!allowGrid && gridLeafAttr)
      return emitOpError() << "mechanism '" << mechanism
                           << "' must not carry grid_decode_leaf";
    if (!allowTernary && ternaryLeafAttr)
      return emitOpError() << "mechanism '" << mechanism
                           << "' must not carry ternary_decode_leaf";
    if (!allowEntry && entryLanes)
      return emitOpError() << "mechanism '" << mechanism
                           << "' must not carry codebook_entry_lanes";
    return mlir::success();
  };

  if (isInt8) {
    if (!carrier || carrier.getValue() != "bare_int8" || nibbleBias ||
        minByteOffset || qhByteOffset)
      return emitOpError()
             << "int8-scale requires carrier_kind=\"bare_int8\" and no "
                "nibble-only geometry";
    if (mlir::failed(rejectForeignGeometry(true, false, false, false,
                                           false, false)))
      return mlir::failure();
  } else if (isNibble) {
    if (!carrier || carrier.getValue() != "nibble4" || !nibbleBias)
      return emitOpError()
             << "nibble-decode requires carrier_kind=\"nibble4\" and an "
                "explicit nibble_bias";
    if (mlir::failed(rejectForeignGeometry(true, false, false, false,
                                           false, false)))
      return mlir::failure();
  } else if (isCodebook) {
    if (!parsedCodebook)
      return emitOpError()
             << "codebook-gather requires a recognized codebook_scale_model";
    if (mlir::failed(rejectForeignGeometry(false, true, false, false,
                                           false, false)))
      return mlir::failure();
  } else if (isKQuant) {
    if (!parsedKQuant)
      return emitOpError()
             << "kquant-scale-min requires a recognized kquant_scale_model";
    if (mlir::failed(rejectForeignGeometry(false, false, true, false,
                                           false, false)))
      return mlir::failure();
  } else if (isGrid) {
    if (!parsedGrid)
      return emitOpError()
             << "grid-lookup requires a recognized grid_decode_leaf";
    bool requiresEntry = *parsedGrid != ::weft::GridDecodeLeaf::Iq3Xxs;
    if (requiresEntry && !entryLanes)
      return emitOpError()
             << "selected grid leaf requires construction-owned "
                "codebook_entry_lanes geometry";
    if (mlir::failed(rejectForeignGeometry(false, false, false, true,
                                           false, true)))
      return mlir::failure();
  } else if (isTernary) {
    if (!parsedTernary)
      return emitOpError()
             << "ternary-decode requires a recognized ternary_decode_leaf";
    ::weft::TernaryDecodeLeaf ternaryLeaf = parsedTernary.value();
    bool requiresEntry = ternaryLeaf == ::weft::TernaryDecodeLeaf::Iq1M ||
                         ternaryLeaf == ::weft::TernaryDecodeLeaf::Iq1S;
    if (requiresEntry && !entryLanes)
      return emitOpError()
             << "selected ternary grid leaf requires construction-owned "
                "codebook_entry_lanes geometry";
    if (!requiresEntry && entryLanes)
      return emitOpError()
             << "non-grid ternary leaf must not carry codebook_entry_lanes";
    if (mlir::failed(rejectForeignGeometry(false, false, false, false,
                                           true, true)))
      return mlir::failure();
  } else {
    if (mlir::failed(rejectForeignGeometry(false, false, false, false,
                                           false, false)))
      return mlir::failure();
  }

  mlir::StringAttr loadLMUL = getDequantLoadLmulAttr();
  mlir::IntegerAttr stripLanes = getDequantStripLanesAttr();
  mlir::StringAttr table = getCodebookGatherTableAttr();
  mlir::IntegerAttr entries = getCodebookGatherEntriesAttr();
  bool anyKQuantFields = getKquantHasMinAttr() ||
                         getKquantMinByteOffsetAttr() ||
                         getKquantSubScaleByteOffsetAttr() ||
                         getKquantHasHighBitPlaneAttr() ||
                         getKquantHighBitByteOffsetAttr();
  bool hasKQuantFields = getKquantHasMinAttr() &&
                         getKquantMinByteOffsetAttr() &&
                         getKquantSubScaleByteOffsetAttr() &&
                         getKquantHasHighBitPlaneAttr() &&
                         getKquantHighBitByteOffsetAttr();

  if (!isCodebook && (table || entries))
    return emitOpError() << "mechanism '" << mechanism
                         << "' carries codebook final-plan fields";
  if (!isKQuant && anyKQuantFields)
    return emitOpError() << "mechanism '" << mechanism
                         << "' carries K-quant final-plan fields";

  if (isNibble) {
    if (!loadLMUL || !stripLanes || loadLMUL.getValue() != "m1" ||
        stripLanes.getInt() <= 0)
      return emitOpError()
             << "nibble final plan requires positive strips at load LMUL m1";
  } else if (isCodebook) {
    if (!loadLMUL || !stripLanes || !table || !entries ||
        !::weft::parseCodebookTable(table.getValue()) ||
        entries.getInt() <= 0 || stripLanes.getInt() <= 0 ||
        (loadLMUL.getValue() != "mf2" && loadLMUL.getValue() != "m1" &&
         loadLMUL.getValue() != "m2"))
      return emitOpError()
             << "codebook final plan requires a valid table, entry count, "
                "positive strip and load LMUL in {mf2,m1,m2}";
  } else if (isKQuant) {
    if (!loadLMUL || !stripLanes || !hasKQuantFields ||
        stripLanes.getInt() <= 0 ||
        (loadLMUL.getValue() != "m1" && loadLMUL.getValue() != "m2"))
      return emitOpError()
             << "K-quant final plan requires load/strip and all scale/min/high-bit fields";
    for (llvm::StringRef name : {"kquant_min_byte_offset",
                                 "kquant_sub_scale_byte_offset",
                                 "kquant_high_bit_byte_offset"})
      if (op->getAttrOfType<mlir::IntegerAttr>(name).getInt() < 0)
        return emitOpError() << "K-quant offset '" << name
                             << "' must be non-negative";
  } else if (loadLMUL || stripLanes) {
    return emitOpError() << "mechanism '" << mechanism
                         << "' carries fields owned by another final plan";
  }

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of C "
              "type 'const uint8_t *'";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *'";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the parent "
              "loop region induction variable)";

  return mlir::success();
}

mlir::LogicalResult TypedQuantizeRowLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): kind, the ggml ABI block
  // facts (qk / block_stride), the typed formula leaf, and provenance. A forbidden local
  // element_count/SEW/LMUL/policy attr or an unexpected name is rejected fail-closed
  // (I7); SEW/LMUL/policy live on setvl/with_vl, runtime k on the ABI.
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "block_stride" ||
           name == "quantize_leaf" || name == "encode_model";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.typed_quantize_row_loop_body keeps SEW/LMUL/policy on "
                "setvl/with_vl and runtime k/AVL/VL in the surrounding "
                "control-plane IR";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded {kind, qk, block_stride, "
                "quantize_leaf, encode_model} "
                "attributes; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "typed_quantize_row_loop_body")
    return emitOpError()
           << "currently supports only kind \"typed_quantize_row_loop_body\" for "
              "the bounded streaming quantize_row nb loop surface";
  if (getEncodeModel().empty())
    return emitOpError()
           << "requires non-empty encode_model construction provenance; compute "
              "is selected only by the required typed quantize_leaf";

  // qk / block_stride are positive ggml ABI byte counts the per-block address
  // arithmetic depends on. Read the SIGNED attr view so a NEGATIVE spelling
  // fail-CLOSES the `<= 0` guard (a uint64_t accessor would zero-extend and
  // fail-OPEN); mirrors the TypedDequantizeRowLoopBodyOp positivity gate (I7).
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0 (the QK block element count); got "
                         << getQkAttr().getInt();
  if (getBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires block_stride > 0 (the AoS quant block stride); got "
           << getBlockStrideAttr().getInt();

  if (op->getNumOperands() != 3 || op->getNumResults() != 0)
    return emitOpError()
           << "requires one f32 input pointer, one block_qX output byte pointer, "
              "and one runtime element-count ABI operand, and no results (the "
              "streaming store is the sink)";

  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] f32 activations read for the amax "
              "reduction and the scale)";
  if (!outputBinding || outputBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'uint8_t *' (the ggml block_qX AoS byte buffer the quant stores "
              "write)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index value "
              "feeding the enclosing setvl";

  // Region structure: exactly ONE entry argument -- the block_index induction
  // variable (index). Unlike the block-dot loop ops there is NO loop-carried
  // accumulator (the quantizer STORES to memory), so the region is terminated by the
  // VOID weft_rvv.typed_quantize_row_loop_yield.
  mlir::Block &block = getBody().front();
  if (block.getNumArguments() != 1)
    return emitOpError()
           << "requires the region to carry exactly one entry argument: the "
              "block_index induction variable (streaming encode has no "
              "loop-carried accumulator)";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (block_index) to be index-typed "
              "(the nb block induction variable)";

  TypedQuantizeRowLoopYieldOp yield =
      block.empty()
          ? TypedQuantizeRowLoopYieldOp()
          : llvm::dyn_cast<TypedQuantizeRowLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_quantize_row_loop_yield (the VOID streaming-store "
              "sink)";

  QuantizeRowEncodeCoreOp core;
  for (mlir::Operation &nested : block) {
    if (auto candidate = llvm::dyn_cast<QuantizeRowEncodeCoreOp>(nested)) {
      if (core)
        return emitOpError()
               << "requires exactly one quantize_row_encode_core brick";
      core = candidate;
      continue;
    }
    if (!llvm::isa<TypedQuantizeRowLoopYieldOp>(nested))
      return emitOpError()
             << "only carries one quantize_row_encode_core brick followed by "
                "typed_quantize_row_loop_yield";
  }
  if (!core)
    return emitOpError()
           << "requires exactly one quantize_row_encode_core brick";
  if (core.getInput() != getInput() || core.getOutput() != getOutput())
    return emitOpError()
           << "requires the encode core to consume the parent input/output ABI "
              "operands";
  if (core.getQuantizeLeaf() != getQuantizeLeaf() ||
      core.getEncodeModel() != getEncodeModel() || core.getQk() != getQk() ||
      core.getBlockStride() != getBlockStride())
    return emitOpError()
           << "requires parent/core typed leaf, provenance and shared layout "
              "facts to agree; the verifier does not recompute the formula";

  return mlir::success();
}

mlir::LogicalResult QuantizeRowEncodeCoreOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded attrs: formula-produced typed leaf, provenance, and the ggml ABI block
  // layout facts. A forbidden dataflow attr or an unexpected name fails closed.
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "quantize_leaf" || name == "encode_model" || name == "qk" ||
           name == "block_stride" || name == "scale_byte_offset" ||
           name == "quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.quantize_row_encode_core keeps SEW/LMUL/policy on "
                "setvl/with_vl";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded {quantize_leaf, encode_model, qk, "
                "block_stride, scale_byte_offset, quant_byte_offset} attributes; unexpected "
                "attribute '"
             << attr.getName() << "'";
  }

  if (getEncodeModel().empty())
    return emitOpError()
           << "requires non-empty encode_model construction provenance; compute "
              "is selected only by the required typed quantize_leaf";
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0; got " << getQkAttr().getInt();
  if (getBlockStrideAttr().getInt() <= 0)
    return emitOpError() << "requires block_stride > 0; got "
                         << getBlockStrideAttr().getInt();
  if (getScaleByteOffsetAttr().getInt() < 0)
    return emitOpError() << "requires scale_byte_offset >= 0; got "
                         << getScaleByteOffsetAttr().getInt();
  if (getQuantByteOffsetAttr().getInt() < 0)
    return emitOpError() << "requires quant_byte_offset >= 0; got "
                         << getQuantByteOffsetAttr().getInt();

  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *'";
  if (!outputBinding || outputBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'uint8_t *'";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the parent "
              "loop region induction variable)";

  return mlir::success();
}

mlir::LogicalResult GgmlQuantizeRowQ80Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind plus
  // the AoS block-format facts (qk / block_stride / scale_byte_offset /
  // quant_byte_offset). There is NO resource/scheduling LMUL knob this cut --
  // the strip is pinned at the m8 anchor ggml uses (all 32 block lanes in one
  // e32m8 strip; the reduction fold is m8-shaped). Anything else -- a forbidden
  // local element_count/SEW/LMUL/policy attr, or an unexpected name -- is
  // rejected fail-closed (I7).
  auto isAllowedQuantizeAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "block_stride" ||
           name == "scale_byte_offset" || name == "quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.quantize_row_q8_0 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedQuantizeAttr(attrName))
      return emitOpError()
             << "only accepts the bounded f32->q8_0 quantizer attributes "
                "'kind', 'qk', 'block_stride', 'scale_byte_offset', and "
                "'quant_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_quantize_row_q8_0")
    return emitOpError()
           << "currently supports only kind \"ggml_quantize_row_q8_0\" for the "
              "bounded ggml f32->block_q8_0 activation quantizer typed surface";

  // The block-format facts are the ggml block_q8_0 layout (ggml-common.h:241-245
  // + QK8_0 = 32): a 32-element block, AoS stride 34 (the fp16 d at byte 0, the
  // 32 int8 qs at byte 2). They are bounded mirror facts; any other layout is
  // rejected fail-closed (I7) -- this op is the q8_0 quantizer, not a generic
  // quantizer.
  if (getQk() != 32)
    return emitOpError()
           << "requires qk = 32 (the ggml QK8_0 block length); got " << getQk();
  if (getBlockStride() != 34)
    return emitOpError()
           << "requires block_stride = 34 (the ggml block_q8_0 AoS stride: 2 "
              "fp16 d bytes + 32 int8 qs bytes); got "
           << getBlockStride();
  if (getScaleByteOffset() != 0)
    return emitOpError()
           << "requires scale_byte_offset = 0 (the ggml block_q8_0 fp16 d at "
              "byte 0); got "
           << getScaleByteOffset();
  if (getQuantByteOffset() != 2)
    return emitOpError()
           << "requires quant_byte_offset = 2 (the ggml block_q8_0 int8 qs "
              "after the 2-byte fp16 d); got "
           << getQuantByteOffset();

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one read-only f32 input pointer, one block_q8_0 output "
              "byte-buffer pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, and one f32 LMUL m1 result";

  // ggml's quantize_row_q8_0 reads x[] (const float *) and writes the block_q8_0
  // AoS byte buffer vy (void *, taken as a uint8_t * byte cursor). The
  // byte-exactness depends on the amax reduction running on real f32 lanes, so
  // the input must be a real f32 buffer; the output binds the mutable byte
  // buffer the AoS d (fp16) + qs (int8) stores write into.
  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] f32 activations read for the amax "
              "reduction and the scale)";
  if (!outputBinding || outputBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'uint8_t *' (the ggml block_q8_0 AoS byte buffer the fp16 d "
              "+ int8 qs stores write)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value (ggml's k, n % 32 == 0) feeding the enclosing setvl";

  if (!isGenericRVVVectorF32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<f32, "
              "\"m1\"> for the ggml f32->q8_0 quantizer route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml f32->q8_0 quantizer";

  return mlir::success();
}

mlir::LogicalResult GgmlQuantizeRowQ81Op::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind plus
  // the AoS block-format facts (qk / block_stride / scale/sum/quant byte
  // offsets). There is NO resource/scheduling LMUL knob this cut -- the strip is
  // pinned at the m8 anchor ggml uses (all 32 block lanes in one e32m8 strip).
  // Anything else -- a forbidden local element_count/SEW/LMUL/policy attr, or an
  // unexpected name -- is rejected fail-closed (I7).
  auto isAllowedQuantizeAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "block_stride" ||
           name == "scale_byte_offset" || name == "sum_byte_offset" ||
           name == "quant_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.quantize_row_q8_1 keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedQuantizeAttr(attrName))
      return emitOpError()
             << "only accepts the bounded f32->q8_1 quantizer attributes "
                "'kind', 'qk', 'block_stride', 'scale_byte_offset', "
                "'sum_byte_offset', and 'quant_byte_offset'; unexpected "
                "attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_quantize_row_q8_1")
    return emitOpError()
           << "currently supports only kind \"ggml_quantize_row_q8_1\" for the "
              "bounded ggml f32->block_q8_1 activation quantizer typed surface";

  // The block-format facts are the ggml block_q8_1 layout (ggml-common.h:248-259
  // + QK8_1 = 32): a 32-element block, AoS stride 36 (the fp16 d at byte 0, the
  // fp16 s at byte 2, the 32 int8 qs at byte 4). Bounded mirror facts; any other
  // layout is rejected fail-closed (I7).
  if (getQk() != 32)
    return emitOpError()
           << "requires qk = 32 (the ggml QK8_1 block length); got " << getQk();
  if (getBlockStride() != 36)
    return emitOpError()
           << "requires block_stride = 36 (the ggml block_q8_1 AoS stride: 2 "
              "fp16 d bytes + 2 fp16 s bytes + 32 int8 qs bytes); got "
           << getBlockStride();
  if (getScaleByteOffset() != 0)
    return emitOpError()
           << "requires scale_byte_offset = 0 (the ggml block_q8_1 fp16 d at "
              "byte 0); got "
           << getScaleByteOffset();
  if (getSumByteOffset() != 2)
    return emitOpError()
           << "requires sum_byte_offset = 2 (the ggml block_q8_1 fp16 s after "
              "the 2-byte fp16 d); got "
           << getSumByteOffset();
  if (getQuantByteOffset() != 4)
    return emitOpError()
           << "requires quant_byte_offset = 4 (the ggml block_q8_1 int8 qs "
              "after the fp16 d + fp16 s); got "
           << getQuantByteOffset();

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one read-only f32 input pointer, one block_q8_1 output "
              "byte-buffer pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, and one f32 LMUL m1 result";

  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] f32 activations read for the amax "
              "reduction and the scale)";
  if (!outputBinding || outputBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'uint8_t *' (the ggml block_q8_1 AoS byte buffer the fp16 d "
              "+ fp16 s + int8 qs stores write)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value (ggml's k, n % 32 == 0) feeding the enclosing setvl";

  if (!isGenericRVVVectorF32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<f32, "
              "\"m1\"> for the ggml f32->q8_1 quantizer route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml f32->q8_1 quantizer";

  return mlir::success();
}

mlir::LogicalResult GgmlQuantizeRowQ8KOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind plus
  // the AoS block-format facts (qk / block_stride / scale/quant/bsums byte
  // offsets). There is NO resource/scheduling LMUL knob this cut -- the strip
  // fold rides ggml's e32m8 vlmax anchor. Anything else -- a forbidden local
  // element_count/SEW/LMUL/policy attr, or an unexpected name -- is rejected
  // fail-closed (I7).
  auto isAllowedQuantizeAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "qk" || name == "block_stride" ||
           name == "scale_byte_offset" || name == "quant_byte_offset" ||
           name == "bsums_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.quantize_row_q8_K keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedQuantizeAttr(attrName))
      return emitOpError()
             << "only accepts the bounded f32->q8_K quantizer attributes "
                "'kind', 'qk', 'block_stride', 'scale_byte_offset', "
                "'quant_byte_offset', and 'bsums_byte_offset'; unexpected "
                "attribute '"
             << attr.getName() << "'";
  }

  if (getKind() != "ggml_quantize_row_q8_K")
    return emitOpError()
           << "currently supports only kind \"ggml_quantize_row_q8_K\" for the "
              "bounded ggml f32->block_q8_K activation quantizer typed surface";

  // The block-format facts are the ggml block_q8_K layout (ggml-common.h:360-366
  // + QK_K = 256): a 256-element super-block, AoS stride 292 (the FLOAT d at byte
  // 0, the 256 int8 qs at byte 4, the 16 int16 bsums at byte 260). Bounded mirror
  // facts; any other layout is rejected fail-closed (I7).
  if (getQk() != 256)
    return emitOpError()
           << "requires qk = 256 (the ggml QK_K super-block length); got "
           << getQk();
  if (getBlockStride() != 292)
    return emitOpError()
           << "requires block_stride = 292 (the ggml block_q8_K AoS stride: 4 "
              "float d bytes + 256 int8 qs bytes + 32 int16 bsums bytes); got "
           << getBlockStride();
  if (getScaleByteOffset() != 0)
    return emitOpError()
           << "requires scale_byte_offset = 0 (the ggml block_q8_K float d at "
              "byte 0); got "
           << getScaleByteOffset();
  if (getQuantByteOffset() != 4)
    return emitOpError()
           << "requires quant_byte_offset = 4 (the ggml block_q8_K int8 qs "
              "after the 4-byte float d); got "
           << getQuantByteOffset();
  if (getBsumsByteOffset() != 260)
    return emitOpError()
           << "requires bsums_byte_offset = 260 (the ggml block_q8_K int16 "
              "bsums after the float d + 256 int8 qs); got "
           << getBsumsByteOffset();

  if (op->getNumOperands() != 4 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one read-only f32 input pointer, one block_q8_K output "
              "byte-buffer pointer, one runtime element-count runtime ABI "
              "operand, one !weft_rvv.vl operand, and one f32 LMUL m1 result";

  RuntimeABIValueOp inputBinding = getInput().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!inputBinding || inputBinding.getCType() != "const float *")
    return emitOpError()
           << "requires the input operand to bind a runtime ABI value of C type "
              "'const float *' (the ggml x[] f32 activations read for the "
              "min/max reduction and the scale)";
  if (!outputBinding || outputBinding.getCType() != "uint8_t *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'uint8_t *' (the ggml block_q8_K AoS byte buffer the float d "
              "+ int8 qs + int16 bsums stores write)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value (ggml's k, n % 256 == 0) feeding the enclosing setvl";

  if (!isGenericRVVVectorF32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type !weft_rvv.vector<f32, "
              "\"m1\"> for the ggml f32->q8_K quantizer route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the ggml f32->q8_K quantizer";

  return mlir::success();
}

mlir::LogicalResult MaskedWideningDotReduceOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.masked_widening_dot_reduce keeps mask "
                "provenance, source/result SEW/LMUL/policy on typed values "
                "and setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";

    if (!isAllowedMaskedWideningDotReduceAttr(attrName))
      return emitOpError()
             << "only accepts generic masked widening dot-product reduction "
                "attributes 'kind', 'mask_role', 'mask_source', "
                "'mask_memory_form', 'accumulator_layout', 'result_layout', "
                "and 'dot_product_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericMaskedWideningDotReduceKind(getKind()))
    return emitOpError()
           << "currently supports only kind "
              "\"signed_masked_widening_dot_reduce_add\" for the bounded "
              "Stage 2 masked widening dot-product reduction route";
  if (!isSupportedTypedComputedMaskMemoryRole(getMaskRole()))
    return emitOpError()
           << "currently supports only mask_role "
              "\"predicate-mask-produced-by-compare\" for the bounded "
              "Stage 2 masked widening dot-product reduction route";
  if (!isSupportedTypedComputedMaskMemoryMaskSource(getMaskSource()))
    return emitOpError()
           << "currently supports only mask_source "
              "\"compare-produced-mask-same-vl-scope\" for the bounded "
              "Stage 2 masked widening dot-product reduction route";
  if (!isSupportedTypedComputedMaskMemoryMaskMemoryForm(getMaskMemoryForm()))
    return emitOpError()
           << "currently supports only mask_memory_form "
              "\"compare-produced-mask\" for the bounded Stage 2 masked "
              "widening dot-product reduction route";
  if (!isSupportedGenericWideningDotReduceAccumulatorLayout(
          getAccumulatorLayout()))
    return emitOpError()
           << "currently supports only accumulator_layout "
              "\"scalar-i32-seed-lane0-from-accumulator-input\" for the "
              "bounded Stage 2 masked widening dot-product reduction route";
  if (!isSupportedGenericWideningDotReduceResultLayout(getResultLayout()))
    return emitOpError()
           << "currently supports only result_layout "
              "\"store-dot-reduction-lane0-to-output-scalar\" for the "
              "bounded Stage 2 masked widening dot-product reduction route";
  if (!isSupportedGenericWideningDotProductRelation(
          getDotProductRelation()))
    return emitOpError()
           << "currently supports only dot_product_relation "
              "\"signed-i16mf2xi16mf2-reduce-plus-i32-scalar-to-i32\" for "
              "the bounded Stage 2 masked widening dot-product reduction "
              "route";

  if (op->getNumOperands() != 5 || op->getNumResults() != 1)
    return emitOpError()
           << "requires compare-produced mask, lhs and rhs i16 generic RVV "
              "vector operands, one i32 accumulator seed runtime ABI operand, "
              "one !weft_rvv.vl operand, and one i32 generic RVV vector result";
  if (!isGenericRVVVectorI16MF2(getLhs().getType()) ||
      !isGenericRVVVectorI16MF2(getRhs().getType()))
    return emitOpError()
           << "requires lhs and rhs source vectors to have type "
              "!weft_rvv.vector<i16, \"mf2\"> for the bounded signed masked "
              "widening dot-product reduction route";
  if (!isGenericRVVVectorI32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector to have type "
              "!weft_rvv.vector<i32, \"m1\"> for the bounded signed masked "
              "widening dot-product reduction route";
  if (!llvm::isa<RuntimeABIValueType>(getAccumulatorSeed().getType()))
    return emitOpError()
           << "requires accumulator seed operand to have "
              "!weft_rvv.runtime_abi_value type";
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getAccumulatorSeed(), "accumulator seed",
          {weft::support::RuntimeABIParameterRole::
               AccumulatorInputBuffer})))
    return mlir::failure();
  RuntimeABIValueOp seedBinding =
      getAccumulatorSeed().getDefiningOp<RuntimeABIValueOp>();
  if (!seedBinding || seedBinding.getCType() != "const int32_t *")
    return emitOpError()
           << "requires accumulator seed operand C type 'const int32_t *' "
              "for the bounded signed masked widening dot-product reduction "
              "route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto compare = getMask().getDefiningOp<CompareOp>();
  if (!compare)
    return emitOpError()
           << "requires mask operand to be produced by weft_rvv.compare "
              "inside the selected RVV typed body";
  if (compare.getKind() != "slt")
    return emitOpError()
           << "requires mask-producing weft_rvv.compare to use kind "
              "\"slt\" for the bounded computed-mask widening dot-product "
              "reduction route";
  if (compare.getVl() != getVl())
    return emitOpError()
           << "requires mask-producing weft_rvv.compare to consume the same "
              "!weft_rvv.vl token as weft_rvv.masked_widening_dot_reduce";
  if (compare->getParentOp() != op->getParentOp())
    return emitOpError()
           << "requires mask-producing weft_rvv.compare to be in the same "
              "weft_rvv.with_vl body as "
              "weft_rvv.masked_widening_dot_reduce";
  if (mlir::failed(verifyGenericMaskTypeForWithVL(op, getMask(), "mask")))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit "
              "result SEW/LMUL metadata for masked widening dot-product "
              "reduction";
  if (!isRVVSelectedBodyM1Config(expectedSEW.getInt(),
                                 expectedLMUL.getValue()))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl result config to be "
              "SEW32 LMUL m1 for the bounded signed masked widening "
              "dot-product reduction route";
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for masked widening dot-product reduction";

  return mlir::success();
}

mlir::LogicalResult WideningConvertOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.widening_convert keeps source/destination "
                "SEW/LMUL/policy on typed vector values and setvl/with_vl, "
                "runtime n/AVL/VL in the surrounding control-plane IR, and "
                "rejects deleted local element_count metadata";

    if (!isAllowedWideningConvertAttr(attrName))
      return emitOpError()
             << "only accepts generic widening conversion attribute 'kind"
             << "'; unexpected attribute '" << attr.getName() << "'";
  }

  if (!isSupportedGenericWideningConvertKind(getKind()))
    return emitOpError()
           << "currently supports only kind \"widen_i32_to_i64\" or "
              "\"sign_extend_widen_vf2\" for the bounded Stage 2 widening "
              "conversion routes";

  if (op->getNumOperands() != 2 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one source generic RVV vector operand, one "
              "!weft_rvv.vl operand, and one destination generic RVV vector "
              "result";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError()
           << "requires runtime VL operand to have !weft_rvv.vl type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  auto expectedSEW =
      (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
  auto expectedLMUL =
      (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
  if (!expectedSEW || !expectedLMUL)
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit "
              "destination SEW/LMUL metadata for widening conversion";

  if (getKind() == "widen_i32_to_i64") {
    if (!isGenericRVVVectorI32M1(getSource().getType()))
      return emitOpError()
             << "requires source vector type to be "
                "!weft_rvv.vector<i32, \"m1\"> for the bounded signed "
                "i32-to-i64 widening conversion route";
    if (!isGenericRVVVectorI64M2(getResult().getType()))
      return emitOpError()
             << "requires result vector type to be "
                "!weft_rvv.vector<i64, \"m2\"> for the bounded signed "
                "i32-to-i64 widening conversion route";
    if (!isRVVSelectedBodyI64M2Config(expectedSEW.getInt(),
                                      expectedLMUL.getValue()))
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl destination config to "
                "be SEW64 LMUL m2 for the bounded signed i32-to-i64 "
                "widening conversion route";
  } else {
    if (!isGenericRVVVectorI16MF2(getSource().getType()))
      return emitOpError()
             << "requires source vector type to be "
                "!weft_rvv.vector<i16, \"mf2\"> for the bounded signed "
                "i16-to-i32 widening conversion route";
    if (!isGenericRVVVectorI32M1(getResult().getType()))
      return emitOpError()
             << "requires result vector type to be "
                "!weft_rvv.vector<i32, \"m1\"> for the bounded signed "
                "i16-to-i32 widening conversion route";
    if (!isRVVSelectedBodyM1Config(expectedSEW.getInt(),
                                   expectedLMUL.getValue()))
      return emitOpError()
             << "requires enclosing weft_rvv.with_vl destination config to "
                "be SEW32 LMUL m1 for the bounded signed i16-to-i32 "
                "widening conversion route";
  }
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for widening conversion";

  return mlir::success();
}

mlir::LogicalResult DequantizeOp::verify() {
  mlir::Operation *op = getOperation();

  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.dequantize keeps source/result dtype, "
                "SEW/LMUL/policy, and runtime scale authority on typed vector "
                "values, runtime ABI SSA, and setvl/with_vl, and rejects "
                "deleted local element_count metadata";

    if (!isAllowedDequantizeAttr(attrName))
      return emitOpError()
             << "only accepts generic dequantization attributes 'kind' and "
                "'dequant_relation'; unexpected attribute '"
             << attr.getName() << "'";
  }

  if (!isSupportedGenericDequantizeKind(getKind()))
    return emitOpError()
           << "currently supports only kind \"i32_to_f32_scaled\" for the "
              "bounded Stage 2 i32-to-f32 dequantization route";
  if (!isSupportedGenericDequantizeRelation(getDequantRelation()))
    return emitOpError()
           << "currently supports only dequant_relation "
              "\"signed-i32m1-to-f32m1-scale-f32\" for the bounded Stage 2 "
              "i32-to-f32 dequantization route";

  if (op->getNumOperands() != 3 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one i32 source generic RVV vector operand, one "
              "runtime f32 scale ABI operand, one !weft_rvv.vl operand, and "
              "one f32 destination generic RVV vector result";
  if (!isGenericRVVVectorI32M1(getSource().getType()))
    return emitOpError()
           << "requires source vector type to be "
              "!weft_rvv.vector<i32, \"m1\"> for the bounded i32-to-f32 "
              "dequantization route";
  if (!isGenericRVVVectorF32M1(getResult().getType()))
    return emitOpError()
           << "requires result vector type to be "
              "!weft_rvv.vector<f32, \"m1\"> for the bounded i32-to-f32 "
              "dequantization route";
  if (!llvm::isa<RuntimeABIValueType>(getScale().getType()))
    return emitOpError()
           << "requires scale operand to have !weft_rvv.runtime_abi_value "
              "type";
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getScale(), "runtime scale",
          {weft::support::RuntimeABIParameterRole::
               DequantScaleValue})))
    return mlir::failure();
  RuntimeABIValueOp scaleBinding = getScale().getDefiningOp<RuntimeABIValueOp>();
  if (!scaleBinding || scaleBinding.getCType() != "float")
    return emitOpError()
           << "requires runtime scale operand C type 'float' for the bounded "
              "i32-to-f32 dequantization route";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError()
           << "requires runtime VL operand to have !weft_rvv.vl type";
  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();

  // Deferred-wide dequant (N3 max-legal-LMUL schedule): the dequant sources the
  // trailing weft_rvv.standalone_reduce (i32m1) whose input is the i32m8
  // weft_rvv.widening_accumulate. The source/result dtype (i32m1 -> f32m1) is
  // the SAME as the narrow path; only the enclosing with_vl is the strip config
  // (SEW8 LMUL m2), so the SEW32-pinned result-vector check does not apply. This
  // is a PARALLEL branch keyed on the deferred-accumulate structural marker.
  if (auto deferredReduce =
          getSource().getDefiningOp<StandaloneReduceOp>()) {
    if (deferredReduce.getInput().getDefiningOp<WideningAccumulateOp>()) {
      if (deferredReduce.getVl() != getVl())
        return emitOpError()
               << "requires the deferred-wide trailing "
                  "weft_rvv.standalone_reduce to consume the same "
                  "!weft_rvv.vl token as weft_rvv.dequantize";
      if (deferredReduce->getParentOp() != op->getParentOp())
        return emitOpError()
               << "requires the deferred-wide trailing "
                  "weft_rvv.standalone_reduce to be in the same "
                  "weft_rvv.with_vl body as weft_rvv.dequantize";
      // Source i32m1 / result f32m1 already checked above; the deferred-wide
      // path keeps those, and skips the SEW32/m1 with_vl pin (strip is SEW8/m2).
      return mlir::success();
    }
  }

  // NARROW byte-anchor dequant (Track B auto-lowering: the dequant rung ON the
  // byte-anchor widening dot-reduce front door): the dequant sources a narrow
  // weft_rvv.standalone_reduce (i32m1) whose input is a weft_rvv.widening_product
  // (NOT the deferred-wide weft_rvv.widening_accumulate). The source/result dtype
  // (i32m1 -> f32m1) is the SAME as the SEW32/m1 grouped path -- already checked
  // above; the ONLY difference is the enclosing with_vl is the SEW8 byte-anchor
  // strip config (LMUL m1 or m2), so the SEW32-pinned source/result-vector checks
  // do NOT apply. This is a PARALLEL branch keyed BOTH on the widening_product
  // marker AND the SEW8 byte-anchor scope: the SEW32/m1 grouped dequant body ALSO
  // carries a widening_product-sourced reduce, so gating on the product op alone
  // would wrongly intercept it and drop its SEW32 pin. The byte-anchor scope gate
  // (parallel to StandaloneReduceOp::verify) lets the SAME generic dequant body
  // flip e8m2/i16m4 vs e8m1/i16m2 by capability, while the grouped SEW32 path
  // falls through to the existing SEW32 pin unchanged.
  if (auto narrowReduce = getSource().getDefiningOp<StandaloneReduceOp>()) {
    if (auto product =
            narrowReduce.getInput().getDefiningOp<WideningProductOp>()) {
      auto scopeSEW = (*withVL)->getAttrOfType<mlir::IntegerAttr>(kSEWAttrName);
      auto scopeLMUL = (*withVL)->getAttrOfType<mlir::StringAttr>(kLMULAttrName);
      const bool isByteAnchorScope =
          scopeSEW && scopeLMUL &&
          scopeSEW.getInt() == getRVVSEW8Bits() &&
          (scopeLMUL.getValue() == getRVVLMULM1() ||
           scopeLMUL.getValue() == getRVVLMULM2());
      if (isByteAnchorScope) {
        if (narrowReduce.getKind() != "signed_widening_reduce_add" ||
            product.getKind() != "signed_widening_product")
          return emitOpError()
                 << "requires the byte-anchor source product-reduction chain to "
                    "use signed_widening_product followed by "
                    "signed_widening_reduce_add";
        if (narrowReduce.getVl() != getVl() || product.getVl() != getVl())
          return emitOpError()
                 << "requires the byte-anchor source product and "
                    "weft_rvv.standalone_reduce to consume the same "
                    "!weft_rvv.vl token as weft_rvv.dequantize";
        if (narrowReduce->getParentOp() != op->getParentOp() ||
            product->getParentOp() != op->getParentOp())
          return emitOpError()
                 << "requires the byte-anchor source product-reduction chain to "
                    "be in the same weft_rvv.with_vl body as weft_rvv.dequantize";
        // Source i32m1 / result f32m1 already checked above; the byte-anchor
        // narrow path keeps those, and skips the SEW32/m1 with_vl pin (the strip
        // is SEW8/m{1,2}).
        return mlir::success();
      }
      // Not a byte-anchor scope -> fall through to the SEW32/m1 grouped pin.
    }
  }

  auto sourceLoad = getSource().getDefiningOp<LoadOp>();
  auto sourceReduction = getSource().getDefiningOp<StandaloneReduceOp>();
  if (!sourceLoad && !sourceReduction)
    return emitOpError()
           << "requires source vector to be produced by weft_rvv.load or by "
              "a bounded weft_rvv.widening_product -> "
              "weft_rvv.standalone_reduce chain inside the selected RVV "
              "typed body";
  if (sourceLoad) {
    if (sourceLoad.getVl() != getVl())
      return emitOpError()
             << "requires source-producing weft_rvv.load to consume the same "
                "!weft_rvv.vl token as weft_rvv.dequantize";
    if (sourceLoad->getParentOp() != op->getParentOp())
      return emitOpError()
             << "requires source-producing weft_rvv.load to be in the same "
                "weft_rvv.with_vl body as weft_rvv.dequantize";
  }
  if (sourceReduction) {
    // The reduce input is either a plain widening product or the signed packed-i4
    // nibble-unpack widening product (the Stage-3 typed packed-i4 surface). Both
    // are bounded i8mf4 -> i16mf2 signed product chains feeding the i32 reduce.
    mlir::Operation *productOp = sourceReduction.getInput().getDefiningOp();
    auto product = llvm::dyn_cast_or_null<WideningProductOp>(productOp);
    auto packed =
        llvm::dyn_cast_or_null<PackedI4NibbleUnpackProductOp>(productOp);
    if (!product && !packed)
      return emitOpError()
             << "requires source-producing weft_rvv.standalone_reduce to "
                "consume a bounded weft_rvv.widening_product or "
                "weft_rvv.packed_i4_nibble_unpack_product result for the "
                "low-precision product-reduction dequantization route";
    const bool productKindOK =
        product ? product.getKind() == "signed_widening_product"
                : packed.getKind() == "signed_packed_i4_nibble_unpack_product";
    if (sourceReduction.getKind() != "signed_widening_reduce_add" ||
        !productKindOK)
      return emitOpError()
             << "requires source-producing product-reduction chain to use "
                "signed_widening_product or "
                "signed_packed_i4_nibble_unpack_product followed by "
                "signed_widening_reduce_add";
    mlir::Value productVL = product ? product.getVl() : packed.getVl();
    if (sourceReduction.getVl() != getVl() || productVL != getVl())
      return emitOpError()
             << "requires source-producing product and "
                "weft_rvv.standalone_reduce to consume the same "
                "!weft_rvv.vl token as weft_rvv.dequantize";
    if (sourceReduction->getParentOp() != op->getParentOp() ||
        productOp->getParentOp() != op->getParentOp())
      return emitOpError()
             << "requires source-producing product-reduction chain to be in "
                "the same weft_rvv.with_vl body as weft_rvv.dequantize";
  }

  if (mlir::failed(verifyGenericVectorTypeForWithVL(op, getSource(),
                                                    "source")))
    return mlir::failure();
  return verifyDequantizeResultVectorForWithVL(op, getResult(), "result");
}

mlir::LogicalResult BlockFp16ScaleProductOp::verify() {
  mlir::Operation *op = getOperation();

  if (getKind() != "dual_fp16_per_block_scale_product")
    return emitOpError()
           << "currently supports only kind "
              "\"dual_fp16_per_block_scale_product\" for the bounded per-block "
              "dual-fp16 scale reconstruction surface";
  if (getScaleModel() != "dual-fp16-per-block-d_x.d_y")
    return emitOpError()
           << "currently supports only scale_model "
              "\"dual-fp16-per-block-d_x.d_y\" (ggml's q8_0 scale order: the "
              "two per-block fp16 scales are multiplied FIRST)";

  // Additive loop-capable extension (M-FLAT step 3): the OPTIONAL block_index
  // operand toggles the per-block-source form. Present => the two fp16 scale
  // headers live at `base + block_index*stride`; absent => the single-block
  // backward-compat form where the imported ABI base IS the block base.
  mlir::Value blockIndex = getBlockIndex();
  bool hasBlockIndex = static_cast<bool>(blockIndex);

  unsigned expectedOperands = hasBlockIndex ? 3 : 2;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires two imported runtime ABI block-base operands (the lhs "
              "and rhs per-block fp16 scale sources), one optional block_index "
              "induction operand, and one f32 scalar result";

  if (!llvm::isa<RuntimeABIValueType>(getLhsScaleBase().getType()))
    return emitOpError()
           << "requires lhs_scale_base operand to have "
              "!weft_rvv.runtime_abi_value type";
  if (!llvm::isa<RuntimeABIValueType>(getRhsScaleBase().getType()))
    return emitOpError()
           << "requires rhs_scale_base operand to have "
              "!weft_rvv.runtime_abi_value type";
  // The base-import contract is NOT relaxed by the loop extension: both bases
  // stay imported ABI block-0 pointers with the LHS/RHS input-buffer roles; the
  // per-block form only ADDS the loop offset on top of these imported bases.
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getLhsScaleBase(), "lhs scale base",
          {weft::support::RuntimeABIParameterRole::LHSInputBuffer})))
    return mlir::failure();
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getRhsScaleBase(), "rhs scale base",
          {weft::support::RuntimeABIParameterRole::RHSInputBuffer})))
    return mlir::failure();

  if (hasBlockIndex) {
    // The per-block AoS block strides the `base + block_index*stride` address
    // arithmetic depends on are hard-required in the loop form (I7).
    if (!getLhsBlockStride() || !getRhsBlockStride())
      return emitOpError()
             << "requires both lhs_block_stride and rhs_block_stride when "
                "block_index is present (the per-block AoS block strides the "
                "`base + block_index*stride` address arithmetic depends on)";
    if (*getLhsBlockStride() == 0 || *getRhsBlockStride() == 0)
      return emitOpError()
             << "requires lhs_block_stride and rhs_block_stride to be positive "
                "AoS block strides";
    if (!llvm::isa<mlir::IndexType>(blockIndex.getType()))
      return emitOpError()
             << "requires block_index to be index-typed (the enclosing loop op "
                "induction variable)";
    // Structural: block_index must be the induction variable (region argument
    // 0) of the enclosing weft_rvv.typed_flat_block_dot_loop_body region. SSA
    // scoping already guarantees this op is nested in that region, so the
    // block-arg owner check is sufficient (I7 fail-closed: a non-loop or
    // non-induction index value is rejected).
    auto blockArg = llvm::dyn_cast<mlir::BlockArgument>(blockIndex);
    if (!blockArg || blockArg.getArgNumber() != 0 ||
        !llvm::isa_and_nonnull<TypedFlatBlockDotLoopBodyOp>(
            blockArg.getOwner()->getParentOp()))
      return emitOpError()
             << "requires block_index to be the induction variable (region "
                "argument 0) of an enclosing "
                "weft_rvv.typed_flat_block_dot_loop_body region";
  } else {
    // Single-block backward-compat form: the per-block stride attrs are
    // meaningless without a block_index and are rejected fail-closed.
    if (getLhsBlockStride() || getRhsBlockStride())
      return emitOpError()
             << "lhs_block_stride / rhs_block_stride are only valid with a "
                "present block_index; the single-block form imports fixed ABI "
                "scale bases with no per-block stride";
  }

  if (!getResult().getType().isF32())
    return emitOpError()
           << "requires an f32 scalar result (f32 fully covers the fp16 "
              "domain, so the dual-fp16 scale reconstruction is byte-exact by "
              "construction)";

  return mlir::success();
}

mlir::LogicalResult BlockFp16MinProductOp::verify() {
  mlir::Operation *op = getOperation();

  if (getKind() != "dual_fp16_per_block_min_product")
    return emitOpError()
           << "currently supports only kind "
              "\"dual_fp16_per_block_min_product\" for the bounded per-block "
              "dual-fp16 MIN/SUM correction product surface";
  if (getScaleModel() != "dual-fp16-per-block-m_x.s_y")
    return emitOpError()
           << "currently supports only scale_model "
              "\"dual-fp16-per-block-m_x.s_y\" (ggml's Family-B correction: the "
              "per-block MIN m_x and precomputed activation sum s_y are "
              "multiplied)";

  // Additive loop-capable extension (mirrors block_fp16_scale_product): the
  // OPTIONAL block_index operand toggles the per-block-source form. Present =>
  // the two fp16 correction headers live at `base + block_index*stride`;
  // absent => the single-block form where the imported ABI base IS the block
  // base.
  mlir::Value blockIndex = getBlockIndex();
  bool hasBlockIndex = static_cast<bool>(blockIndex);

  unsigned expectedOperands = hasBlockIndex ? 3 : 2;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires two imported runtime ABI block-base operands (the lhs "
              "min and rhs sum per-block fp16 correction sources), one optional "
              "block_index induction operand, and one f32 scalar result";

  if (!llvm::isa<RuntimeABIValueType>(getLhsMinBase().getType()))
    return emitOpError()
           << "requires lhs_min_base operand to have "
              "!weft_rvv.runtime_abi_value type";
  if (!llvm::isa<RuntimeABIValueType>(getRhsSumBase().getType()))
    return emitOpError()
           << "requires rhs_sum_base operand to have "
              "!weft_rvv.runtime_abi_value type";
  // The base-import contract is NOT relaxed by the loop extension: both bases
  // stay imported ABI block-0 pointers with the LHS/RHS input-buffer roles.
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getLhsMinBase(), "lhs min base",
          {weft::support::RuntimeABIParameterRole::LHSInputBuffer})))
    return mlir::failure();
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getRhsSumBase(), "rhs sum base",
          {weft::support::RuntimeABIParameterRole::RHSInputBuffer})))
    return mlir::failure();

  if (hasBlockIndex) {
    if (!getLhsBlockStride() || !getRhsBlockStride())
      return emitOpError()
             << "requires both lhs_block_stride and rhs_block_stride when "
                "block_index is present (the per-block AoS block strides the "
                "`base + block_index*stride` address arithmetic depends on)";
    if (*getLhsBlockStride() == 0 || *getRhsBlockStride() == 0)
      return emitOpError()
             << "requires lhs_block_stride and rhs_block_stride to be positive "
                "AoS block strides";
    if (!llvm::isa<mlir::IndexType>(blockIndex.getType()))
      return emitOpError()
             << "requires block_index to be index-typed (the enclosing loop op "
                "induction variable)";
    auto blockArg = llvm::dyn_cast<mlir::BlockArgument>(blockIndex);
    if (!blockArg || blockArg.getArgNumber() != 0 ||
        !llvm::isa_and_nonnull<TypedFlatBlockDotLoopBodyOp>(
            blockArg.getOwner()->getParentOp()))
      return emitOpError()
             << "requires block_index to be the induction variable (region "
                "argument 0) of an enclosing "
                "weft_rvv.typed_flat_block_dot_loop_body region";
  } else {
    if (getLhsBlockStride() || getRhsBlockStride())
      return emitOpError()
             << "lhs_block_stride / rhs_block_stride are only valid with a "
                "present block_index; the single-block form imports fixed ABI "
                "min/sum bases with no per-block stride";
  }

  if (!getResult().getType().isF32())
    return emitOpError()
           << "requires an f32 scalar result (f32 fully covers the fp16 "
              "domain, so the dual-fp16 MIN/SUM correction reconstruction is "
              "byte-exact by construction)";

  return mlir::success();
}

mlir::LogicalResult BlockFiveBitQhSourceOp::verify() {
  mlir::Operation *op = getOperation();

  if (getKind() != "block_five_bit_qh_source")
    return emitOpError()
           << "currently supports only kind \"block_five_bit_qh_source\" for the "
              "bounded per-block five-bit qh 32-bit field source brick surface";

  // Additive loop-capable extension (mirrors block_fp16_min_product): the OPTIONAL
  // block_index operand toggles the per-block-source form. Present => the qh header
  // lives at `qh_base + block_index*block_stride`; absent => the single-block form
  // where the imported ABI base IS the block base.
  mlir::Value blockIndex = getBlockIndex();
  bool hasBlockIndex = static_cast<bool>(blockIndex);

  unsigned expectedOperands = hasBlockIndex ? 2 : 1;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires one imported runtime ABI weight block-base operand (the "
              "qh field source), one optional block_index induction operand, and "
              "one scalar i32 result";

  if (!llvm::isa<RuntimeABIValueType>(getQhBase().getType()))
    return emitOpError()
           << "requires qh_base operand to have !weft_rvv.runtime_abi_value type";
  // The qh field lives WITHIN the weight block, so the base is the weight ABI
  // base (the SAME LHS input-buffer the nibble weight load names).
  if (mlir::failed(verifyRuntimeABIValueOperandRole(
          op, getQhBase(), "qh base",
          {weft::support::RuntimeABIParameterRole::LHSInputBuffer})))
    return mlir::failure();

  if (hasBlockIndex) {
    if (!getBlockStride())
      return emitOpError()
             << "requires block_stride when block_index is present (the per-block "
                "AoS weight stride the `base + block_index*stride` address "
                "arithmetic depends on)";
    if (*getBlockStride() == 0)
      return emitOpError()
             << "requires block_stride to be a positive AoS block stride";
    if (!llvm::isa<mlir::IndexType>(blockIndex.getType()))
      return emitOpError()
             << "requires block_index to be index-typed (the enclosing loop op "
                "induction variable)";
    auto blockArg = llvm::dyn_cast<mlir::BlockArgument>(blockIndex);
    if (!blockArg || blockArg.getArgNumber() != 0 ||
        !llvm::isa_and_nonnull<TypedFlatBlockDotLoopBodyOp>(
            blockArg.getOwner()->getParentOp()))
      return emitOpError()
             << "requires block_index to be the induction variable (region "
                "argument 0) of an enclosing "
                "weft_rvv.typed_flat_block_dot_loop_body region";
  } else {
    if (getBlockStride())
      return emitOpError()
             << "block_stride is only valid with a present block_index; the "
                "single-block form imports a fixed ABI weight base with no "
                "per-block stride";
  }

  if (!getResult().getType().isInteger(32))
    return emitOpError()
           << "requires a scalar i32 result (the gate-only qh-source token the "
              "five-bit product op names; the bytes are re-read from qh_base + "
              "qh_byte_offset in the emitter)";

  return mlir::success();
}

mlir::LogicalResult BlockComputedScaleDequantOp::verify() {
  mlir::Operation *op = getOperation();

  // Standalone bounded surface checks by string equality (deliberately NOT the
  // shared weft_rvv.dequantize helpers): this op is APPENDED with zero reach
  // into DequantizeOp's contract.
  if (getKind() != "computed_scale_sumi_dequant")
    return emitOpError()
           << "currently supports only kind \"computed_scale_sumi_dequant\" "
              "for the bounded per-block computed-scale i32-sumi dequant fold "
              "surface";
  if (getDequantRelation() != "scalar-i32-sumi-to-f32-computed-scale-f32")
    return emitOpError()
           << "currently supports only dequant_relation "
              "\"scalar-i32-sumi-to-f32-computed-scale-f32\" for the bounded "
              "computed-scale i32-sumi dequant fold surface";

  // Two-operand base form (q8_0 / q4_0 / q5_0, no min term) or three-operand
  // Family-B form (q4_1 / q5_1) with the OPTIONAL min_term. The min_term
  // presence is byte-neutral for the base form (the accessor stays null).
  mlir::Value minTerm = getMinTerm();
  unsigned expectedOperands = minTerm ? 3 : 2;
  if (op->getNumOperands() != expectedOperands || op->getNumResults() != 1)
    return emitOpError()
           << "requires the scalar i32 per-block sumi, the computed f32 "
              "per-block scale, one optional computed f32 min_term, and one f32 "
              "scalar result";

  if (!getSumi().getType().isInteger(32))
    return emitOpError()
           << "requires the sumi operand to be a scalar i32 (the per-block "
              "partial sum consumed by the fp32 fold)";

  // Wall-2 contrast: the computed scale must be a COMPUTED f32 SSA value (the
  // weft_rvv.block_fp16_scale_product output), NOT an imported ABI scale. An
  // imported runtime scale carries the !weft_rvv.runtime_abi_value type, which
  // fails this f32 check -- so requiring f32 fail-closed rejects the
  // imported-scale-only form weft_rvv.dequantize hard-requires (I7).
  if (!getComputedScale().getType().isF32())
    return emitOpError()
           << "requires the computed_scale operand to be a COMPUTED f32 SSA "
              "value (an imported !weft_rvv.runtime_abi_value scale is "
              "rejected: this op consumes the per-block computed scale, not an "
              "imported ABI scale)";

  // The OPTIONAL Family-B min_term (the m_x*s_y product from
  // weft_rvv.block_fp16_min_product) must be a COMPUTED f32 SSA value, same
  // fail-closed contrast as computed_scale (an imported ABI scale carries the
  // !weft_rvv.runtime_abi_value type and fails the f32 check).
  if (minTerm && !minTerm.getType().isF32())
    return emitOpError()
           << "requires the optional min_term operand to be a COMPUTED f32 SSA "
              "value (the m_x*s_y per-block correction product from "
              "weft_rvv.block_fp16_min_product)";

  if (!getResult().getType().isF32())
    return emitOpError()
           << "requires an f32 scalar result (f32 fully covers the scalar i32 "
              "sumi and f32 scale domains, so the fold is byte-exact by "
              "construction)";

  return mlir::success();
}

mlir::LogicalResult CrossBlockF32AccumulateOp::verify() {
  mlir::Operation *op = getOperation();

  // Standalone bounded surface checks by string equality (deliberately NOT the
  // shared i32 intra-strip accumulator helpers): this op is APPENDED with zero
  // reach into WideningAccumulateOp's or DeferredAccumulateOp's contract.
  if (getKind() != "cross_block_f32_scalar_accumulate")
    return emitOpError()
           << "currently supports only kind "
              "\"cross_block_f32_scalar_accumulate\" for the bounded per-block "
              "cross-block f32 accumulate fold surface";
  if (getAccumulateOrder() != "strict-ascending-block-carried")
    return emitOpError()
           << "currently supports only accumulate_order "
              "\"strict-ascending-block-carried\" (ggml's q8_0 accumulation "
              "order: the fp32 fold is applied in STRICT ASCENDING block order, "
              "preserving fp non-associativity)";

  if (op->getNumOperands() != 2 || op->getNumResults() != 1)
    return emitOpError()
           << "requires two operands (the block-carried f32 accumulator and the "
              "per-block f32 term) and one f32 scalar result";

  // Wall-3 contrast: acc, term, and the result must be scalar f32. The two
  // typed accumulators the dialect already carries (widening_accumulate /
  // deferred_accumulate) are i32-INTEGER INTRA-STRIP accumulators -- an i32
  // lane accumulator or a vector value fails the f32 check, so requiring f32
  // fail-closed rejects those wrong-dtype/wrong-scope forms (I7). This is the
  // dedicated cross-block scalar f32 fold, not an intra-strip integer reduce.
  if (!getAcc().getType().isF32())
    return emitOpError()
           << "requires the acc operand to be a scalar f32 (the block-carried "
              "cross-block accumulator; an i32 lane accumulator or a vector "
              "value is rejected -- this is the f32 cross-block fold, not the "
              "i32 intra-strip widening/deferred accumulate)";
  if (!getTerm().getType().isF32())
    return emitOpError()
           << "requires the term operand to be a scalar f32 (the per-block "
              "`(float)sumi * scale` value from "
              "weft_rvv.block_computed_scale_dequant)";
  if (!getResult().getType().isF32())
    return emitOpError()
           << "requires an f32 scalar result (f32 fully covers the accumulator "
              "and term domains, so the cross-block fold is byte-exact by "
              "construction)";

  return mlir::success();
}

mlir::LogicalResult TypedFlatBlockDotLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded surface (I7 fail-closed): the loop op owns the q8_0 SumiTimesScales,
  // q4_0 LeftAssoc, q4_1 ScalePlusMin, and q5_0 ScalesTimesSumi fold trees for
  // the current cohort; the remaining flat fold trees (q5_1 ScalePlusMin, ...)
  // are later.
  if (getKind() != "typed_flat_block_dot_loop_body")
    return emitOpError()
           << "currently supports only kind \"typed_flat_block_dot_loop_body\" "
              "for the bounded flat block dot-product nb loop surface";
  if (getFoldModel() != "sumi_times_scales" && getFoldModel() != "left_assoc" &&
      getFoldModel() != "scale_plus_min" &&
      getFoldModel() != "scales_times_sumi" &&
      getFoldModel() != "flat_binary_two_level" &&
      getFoldModel() != "flat_nvfp4_codebook")
    return emitOpError()
           << "currently supports only fold_model \"sumi_times_scales\" (the "
              "q8_0 `(float)sumi * (d_x * d_y)` fold tree), \"left_assoc\" (the "
              "q4_0 `((float)sumi * d_x) * d_y` fold tree), \"scale_plus_min\" "
              "(the q4_1 `(d_x*d_y)*sumi + m_x*s_y` fold tree), "
              "\"scales_times_sumi\" (the q5_0 `(d_x*d_y)*(float)sumi` fold "
              "tree), \"flat_binary_two_level\" (the q1_0 `d0 * Σ_k(d1_k * "
              "sumi_block_k)` two-level fold, carried by the q1_0 binary-sign "
              "integer-core brick), or \"flat_nvfp4_codebook\" (the nvfp4 "
              "per-sub-block `sumf += (d_y*d_x)*(float)sumi_s` UE4M3-codebook "
              "fold, carried by the nvfp4 codebook integer-core brick); the "
              "other flat fold trees are later steps";

  // Externally-defined ggml block facts: QK and the AoS block strides are
  // positive byte counts the per-block address arithmetic depends on. The
  // positivity gate MUST read the SIGNED attr view (getXAttr().getInt()): the
  // ODS uint64_t accessors (getQk() etc.) zero-extend the i64 attr, so a
  // NEGATIVE value reinterprets as a huge positive count and fail-OPENS the
  // `<= 0` guard (qk=-32 would slip through while qk=0 is rejected). Reading the
  // int64_t signed view fail-CLOSES both non-positive spellings (I7).
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0 (the QK block element count); got "
                         << getQkAttr().getInt();
  if (getWeightBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_block_stride > 0 (the AoS weight block stride); "
              "got "
           << getWeightBlockStrideAttr().getInt();
  if (getActivationBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires activation_block_stride > 0 (the AoS activation block "
              "stride); got "
           << getActivationBlockStrideAttr().getInt();

  // Bounded scheduling knobs, mirroring the monolithic block-dot surface (the
  // *how* -- LMUL / unroll / elision -- never the *what*). Any other spelling
  // is rejected fail-closed (I7).
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul()) {
    if (*coreLmul != "m1" && *coreLmul != "m2" && *coreLmul != "mf4")
      return emitOpError()
             << "only accepts integer_core_lmul \"m1\", \"m2\", or \"mf4\"; got "
                "\""
             << *coreLmul << "\"";
    // Anti-lie fail-closed (I7): the lowering derives the integer-core LMUL from
    // the region's per-block vector loads (the widening/packed product op硬钉s
    // that LMUL via its product_relation), NOT from this attr. So an
    // integer_core_lmul that disagrees with the width the region can actually
    // express would be SILENTLY ignored -- emit ships the region's LMUL core
    // while the attr claims another width (lying IR). Require the attr to match
    // every region integer-core load LMUL, so an unhonorable width fails verify
    // here instead of emitting a mismatched core. This subsumes the format-
    // specific monolith constraints: q4_0's region is硬钉ed i8m1 by
    // "offset-binary-i4m1-x-i8m1x2-to-i16m2", so it rejects m2/mf4 (the
    // "elided-only-at-m1" q4_0 legality); q8_0's region is硬钉ed i8m2, so it
    // keeps the m2 default. The check is skipped on a load-less skeleton region
    // (nothing to express yet; the emit gates those closed downstream).
    LoadOp mismatchedLoad;
    getBody().walk([&](LoadOp load) {
      if (mismatchedLoad)
        return;
      if (auto vecTy =
              llvm::dyn_cast<VectorType>(load.getLoaded().getType())) {
        if (vecTy.getLmul() != *coreLmul)
          mismatchedLoad = load;
      }
    });
    if (mismatchedLoad)
      return emitOpError()
             << "integer_core_lmul \"" << *coreLmul
             << "\" does not match the region integer-core load LMUL \""
             << llvm::cast<VectorType>(mismatchedLoad.getLoaded().getType())
                    .getLmul()
             << "\"; the lowering derives the core LMUL from the region loads, "
                "so a divergent integer_core_lmul would be silently ignored and "
                "emit the region width (attribute-derived-emission lie)";
  }
  int64_t multiBlockFactor = getMultiBlockFactor().value_or(1);
  if (multiBlockFactor != 1 && multiBlockFactor != 2 && multiBlockFactor != 4)
    return emitOpError()
           << "only accepts multi_block_factor 1, 2, or 4; got "
           << multiBlockFactor;
  if (std::optional<llvm::StringRef> stripElision = getStripElision()) {
    if (*stripElision != "robust" && *stripElision != "elided")
      return emitOpError()
             << "only accepts strip_elision \"robust\" or \"elided\"; got \""
             << *stripElision << "\"";
  }
  // fold_structure is the orthogonal fold-SCHEDULE knob (how the pinned §1 fold
  // is issued), not a new arithmetic tree: "per-block" (default) folds each
  // block's scalar term into the running sum as produced; "deferred-ordered"
  // batches the fold into one seed-ordered vfredosum.vs. Any other spelling is
  // rejected fail-closed (I7). Which fold trees / knob combos actually
  // materialize deferred-ordered is an emit-time surface gate (like the
  // multi_block_factor materialization), not a verifier concern.
  if (std::optional<llvm::StringRef> foldStructure = getFoldStructure()) {
    if (*foldStructure != "per-block" && *foldStructure != "deferred-ordered")
      return emitOpError()
             << "only accepts fold_structure \"per-block\" or "
                "\"deferred-ordered\"; got \""
             << *foldStructure << "\"";
  }
  // numerics_tier is the orthogonal ORACLE-selection knob (which fp oracle governs
  // the fold), not an arithmetic tree and not a fold schedule: "strict" (default;
  // absent = strict) pins the §1 byte-exact fold; "relaxed" is the §5 policy-gated
  // reassociation variant (verified against the reassoc-tolerant oracle + a declared
  // ULP bound, admitted only behind numerics.reassoc_ok). Any other spelling is
  // rejected fail-closed (I7). Whether a given fold tree / knob combo actually
  // materializes a relaxed body is an emit-time surface gate (like fold_structure),
  // not a verifier concern.
  if (std::optional<llvm::StringRef> numericsTier = getNumericsTier()) {
    if (*numericsTier != "strict" && *numericsTier != "relaxed")
      return emitOpError()
             << "only accepts numerics_tier \"strict\" or \"relaxed\"; got \""
             << *numericsTier << "\"";
  }

  if (op->getNumOperands() != 4 || op->getNumResults() != 0)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one output pointer, and one runtime element-count runtime ABI "
              "operand, and no results (the scalar store is the sink)";

  // The three buffer operands + element count are runtime ABI values whose C
  // types pin the ggml ABI byte layout the emission depends on (mirroring the
  // monolithic block-dot ops).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS weight byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS activation byte "
              "array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // Region structure: exactly two entry arguments -- the block_index induction
  // variable (index) and the loop-carried f32 accumulator -- terminated by the
  // typed loop yield naming the carried-out f32.
  mlir::Block &block = getBody().front();
  if (block.getNumArguments() != 2)
    return emitOpError()
           << "requires the region to carry exactly two entry arguments: the "
              "block_index induction variable and the loop-carried f32 "
              "accumulator";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (block_index) to be "
              "index-typed (the nb block induction variable)";
  if (!block.getArgument(1).getType().isF32())
    return emitOpError()
           << "requires the second region argument (the loop-carried "
              "accumulator) to be scalar f32";

  TypedFlatBlockDotLoopYieldOp yield =
      block.empty()
          ? TypedFlatBlockDotLoopYieldOp()
          : llvm::dyn_cast<TypedFlatBlockDotLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_flat_block_dot_loop_yield (the carried-out f32 "
              "accumulator)";
  if (!yield.getAccNext().getType().isF32())
    return emitOpError()
           << "requires the loop yield to carry a scalar f32 accumulator";

  return mlir::success();
}

mlir::LogicalResult TypedFlatBlockDotLoopYieldOp::verify() {
  if (!getAccNext().getType().isF32())
    return emitOpError()
           << "requires the carried-out accumulator to be scalar f32 (the "
              "block-carried cross-block accumulator domain)";
  return mlir::success();
}

// The q4_K/q5_K super-block loop op carries a DUAL accumulator: an 8-lane fp32
// VECTOR (!weft_rvv.vector<f32, "m2">, the deferred positive-fold `sums` chain)
// and a scalar f32 (the `sumf` MIN-term chain). The predicate pins that exact
// vector accumulator type.
static bool isF32M2VectorAccumulator(mlir::Type type) {
  auto vector = llvm::dyn_cast<VectorType>(type);
  return vector && vector.getElementType().isF32() &&
         vector.getLmul() == getRVVLMULM2();
}

// The q4_0 16x1-REPACKED GEVM per-strip f32 accumulator sits on ONE of two fold
// LMUL rungs: f32m2 for the mf2 (RVV1.0 fractional) core, f32m4 for the m1
// (RVV0.7 whole-LMUL) core. Both the loop-body region accumulators and the
// dual-fp16 scale-fold brick's acc/acc_next range over this pair; the enclosing
// loop op pins which rung (the core LMUL is the *how*, never the *what*).
static bool isF32M2OrM4VectorAccumulator(mlir::Type type) {
  auto vector = llvm::dyn_cast<VectorType>(type);
  return vector && vector.getElementType().isF32() &&
         (vector.getLmul() == getRVVLMULM2() ||
          vector.getLmul() == getRVVLMULM4());
}

mlir::LogicalResult RepackDualFp16ScaleFoldOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // within-block fp16 scale byte offsets the per-strip dual-fp16 fold needs, and
  // the OPTIONAL integer_core_lmul resource anchor. The per-block strides, qk, the
  // interleave, and the resource-aware strip width are the enclosing loop op's
  // facts. A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "weight_scale_byte_offset" ||
           name == "activation_scale_byte_offset" ||
           name == "integer_core_lmul" || name == "weight_min_byte_offset" ||
           name == "activation_sum_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_dual_fp16_scale_fold keeps SEW/LMUL/policy on "
                "setvl/with_vl, runtime n/AVL/VL in the surrounding control-plane "
                "IR, and rejects deleted local element_count metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded repacked per-strip scale-fold "
                "attributes 'kind', 'weight_scale_byte_offset', "
                "'activation_scale_byte_offset', 'integer_core_lmul', and the "
                "optional q4_1 min-fold pair 'weight_min_byte_offset' / "
                "'activation_sum_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }
  // The q4_1 single MIN-fold facts are a PAIR: either both present (the q4_1 fold
  // adds `acc += m_x*s_y`) or both absent (the q4_0 dual-fp16 fold, no min).
  if (getWeightMinByteOffsetAttr().operator bool() !=
      getActivationSumByteOffsetAttr().operator bool())
    return emitOpError()
           << "requires the q4_1 min-fold facts weight_min_byte_offset and "
              "activation_sum_byte_offset to be present together (both) or absent "
              "together (the q4_0 no-min fold)";

  if (getKind() != "repack_dual_fp16_scale_fold")
    return emitOpError()
           << "currently supports only kind \"repack_dual_fp16_scale_fold\" for "
              "the bounded q4_0 16x1-repacked per-block per-strip dual-fp16 scale "
              "fold typed surface";

  // Bounded resource knob (the *how*, never the *what*): the widening-chain base
  // LMUL {"mf2" RVV1.0 fractional f32m2 fold, "m1" RVV0.7 whole-LMUL f32m4 fold}.
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 fractional "
                "f32m2 fold) or \"m1\" (the RVV0.7 whole-LMUL f32m4 fold); got \""
             << coreLmul << "\"";
  }

  if (op->getNumOperands() != 6 || op->getNumResults() != 1)
    return emitOpError()
           << "requires the repacked weight base, the plain q8_0 activation base, "
              "the per-strip i32 sumi, the loop-carried per-strip f32 "
              "accumulator, one !weft_rvv.vl operand, and one block_index "
              "induction operand, producing one folded-out per-strip f32 vector "
              "accumulator";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  // The consumed sumi is the integer brick's per-strip combined result: i32m2 for
  // the mf2 (RVV1.0 fractional) core, i32m4 for the m1 (RVV0.7 whole-LMUL) core.
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getSumi().getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
      !isGenericRVVSignedOrSignlessIntegerVectorType(
          getSumi().getType(), getRVVSEW32Bits(), getRVVLMULM4()))
    return emitOpError()
           << "requires the consumed sumi to be an i32 !weft_rvv.vector<i32, "
              "\"m2\"> (the mf2 core) or <i32, \"m4\"> (the m1 core)";
  // The loop-carried accumulator + folded-out result are per-strip f32 vectors:
  // f32m2 for the mf2 (RVV1.0 fractional) fold, f32m4 for the m1 (RVV0.7
  // whole-LMUL) fold. Both share the ONE fold LMUL rung, and the consumed sumi
  // must sit on that SAME rung (i32m2 <-> f32m2, i32m4 <-> f32m4).
  if (!isF32M2OrM4VectorAccumulator(getAcc().getType()))
    return emitOpError()
           << "requires the loop-carried accumulator to be a per-strip f32 vector "
              "(!weft_rvv.vector<f32, \"m2\"> the mf2 fold or <f32, \"m4\"> the "
              "m1 whole-LMUL fold)";
  if (getAccNext().getType() != getAcc().getType())
    return emitOpError()
           << "requires the folded-out accumulator to share the loop-carried "
              "accumulator's f32 LMUL rung (both f32m2 or both f32m4)";
  auto accVec = llvm::cast<VectorType>(getAcc().getType());
  auto sumiVec = llvm::cast<VectorType>(getSumi().getType());
  if (sumiVec.getLmul() != accVec.getLmul())
    return emitOpError()
           << "requires the consumed sumi to sit on the same LMUL rung as the "
              "f32 accumulator (i32m2 with f32m2, i32m4 with f32m4)";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked per-strip dual-fp16 scale fold";

  return mlir::success();
}

mlir::LogicalResult TypedSuperBlockBlockDotLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded surface (I7 fail-closed): the super-block loop op owns the q4_K/q5_K
  // two-level scale/min fold tree; any other kind/fold_model spelling is rejected
  // fail-closed.
  if (getKind() != "typed_super_block_block_dot_loop_body")
    return emitOpError()
           << "currently supports only kind "
              "\"typed_super_block_block_dot_loop_body\" for the bounded q4_K/q5_K "
              "super-block block dot-product nb loop surface";
  // W2/W-B: the bounded fold_model set fixes the ARITHMETIC fold tree AND KEYS
  // the accumulator arity: "super_block_two_level_scale_min" is the q4_K/q5_K
  // two-level DUAL fold (`sums += d*(float)aux32` positive fold PLUS
  // `sumf -= dmin*Σ(mins*bsums)` MIN term); "scales_times_sumi" is the q6_K
  // no-min SINGLE fold (`sums += d*(float)aux32` positive fold ONLY, no scalar
  // MIN chain). Any other spelling is rejected fail-closed (I7); a missing/empty
  // fold_model cannot reach this branch (the StrAttr is required by ODS).
  if (getFoldModel() != "super_block_two_level_scale_min" &&
      getFoldModel() != "scales_times_sumi" &&
      getFoldModel() != "scalar_scale_min" &&
      getFoldModel() != "scalar_delta_grid")
    return emitOpError()
           << "currently supports only fold_model "
              "\"super_block_two_level_scale_min\" (the q4_K/q5_K two-level DUAL "
              "`sums += d*(float)aux32` positive fold PLUS the "
              "`sumf -= dmin*Σ(mins*bsums)` MIN term), \"scales_times_sumi\" "
              "(the q6_K no-min SINGLE-VECTOR `sums += d*(float)aux32` positive "
              "fold ONLY), \"scalar_scale_min\" (the q2_K SCALAR "
              "`sumf += dall*isum - dmin*summs` fold), or \"scalar_delta_grid\" "
              "(the iq1_s SCALAR `sumf += d*((float)sumi + IQ1S_DELTA*"
              "(float)sumi1)` ternary-grid delta fold); the other super-block "
              "fold trees are later steps";

  // Externally-defined ggml super-block facts: QK_K and the AoS super-block
  // strides are positive byte counts the per-super-block address arithmetic
  // depends on. Read the SIGNED attr view (getXAttr().getInt()): the uint64_t
  // ODS accessors zero-extend the i64 attr, so a negative value would fail-OPEN
  // the `<= 0` guard (I7).
  if (getQkAttr().getInt() <= 0)
    return emitOpError()
           << "requires qk > 0 (the QK_K super-block element count); got "
           << getQkAttr().getInt();
  if (getWeightBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_block_stride > 0 (the AoS weight super-block "
              "stride); got "
           << getWeightBlockStrideAttr().getInt();
  if (getActivationBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires activation_block_stride > 0 (the AoS activation "
              "super-block stride); got "
           << getActivationBlockStrideAttr().getInt();

  // Bounded scheduling knob, mirroring the q4_K scaled-dot brick surface: the
  // integer-MAC widening-chain base LMUL {"mf2","m1","m2"} (the *how*, never the
  // *what*). Any other spelling is rejected fail-closed (I7).
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul()) {
    if (*coreLmul != "mf2" && *coreLmul != "m1" && *coreLmul != "m2")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\", \"m1\", or \"m2\" (the "
                "q4_K/q5_K Region-C integer-MAC widening-chain base LMUL); got \""
             << *coreLmul << "\"";
  }

  if (op->getNumOperands() != 4 || op->getNumResults() != 0)
    return emitOpError()
           << "requires one weight base pointer, one activation base pointer, "
              "one output pointer, and one runtime element-count runtime ABI "
              "operand, and no results (the scalar store is the sink)";

  // The three buffer operands + element count are runtime ABI values whose C
  // types pin the ggml ABI byte layout the emission depends on (mirroring the
  // flat loop op and the monolithic q4_K block-dot ops).
  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of "
              "C type 'const uint8_t *' (the AoS block_q4_K byte array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI "
              "value of C type 'const uint8_t *' (the AoS block_q8_K byte "
              "array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C "
              "type 'float *' (the ggml *s scalar destination)";
  if (!llvm::isa<mlir::IndexType>(getN().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";

  // W-A: fold_model KEYS the accumulator arity. The q6_K no-min
  // "scales_times_sumi" path carries a SINGLE accumulator: exactly TWO region
  // entry arguments (the super_block_index induction variable + the loop-carried
  // `sums` 8-lane fp32 vector) and a yield naming the `sums` vector ALONE (no
  // `sumf` scalar -- the no-min fold has no MIN chain). A dual (sumf-carrying)
  // yield under this single fold is rejected fail-closed. The q4_K/q5_K dual path
  // below is unchanged.
  if (getFoldModel() == "scales_times_sumi") {
    mlir::Block &block = getBody().front();
    if (block.getNumArguments() != 2)
      return emitOpError()
             << "requires the region to carry exactly two entry arguments for "
                "the single-accumulator no-min fold_model \"scales_times_sumi\": "
                "the super_block_index induction variable and the loop-carried "
                "`sums` 8-lane fp32 vector accumulator (a dual-accumulator region "
                "with a `sumf` scalar is rejected under the no-min fold)";
    if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
      return emitOpError()
             << "requires the first region argument (super_block_index) to be "
                "index-typed (the nb super-block induction variable)";
    if (!isF32M2VectorAccumulator(block.getArgument(1).getType()))
      return emitOpError()
             << "requires the second region argument (the loop-carried `sums` "
                "accumulator) to be an 8-lane fp32 vector "
                "(!weft_rvv.vector<f32, \"m2\">)";
    TypedSuperBlockBlockDotLoopYieldOp yield =
        block.empty()
            ? TypedSuperBlockBlockDotLoopYieldOp()
            : llvm::dyn_cast<TypedSuperBlockBlockDotLoopYieldOp>(&block.back());
    if (!yield)
      return emitOpError()
             << "requires the region to be terminated by "
                "weft_rvv.typed_super_block_block_dot_loop_yield (the single "
                "carried-out `sums` vector accumulator)";
    if (!isF32M2VectorAccumulator(yield.getSumsNext().getType()))
      return emitOpError()
             << "requires the loop yield to carry an 8-lane fp32 vector `sums` "
                "accumulator (!weft_rvv.vector<f32, \"m2\">) as its first operand";
    if (yield.getSumfNext())
      return emitOpError()
             << "the single-accumulator no-min fold_model \"scales_times_sumi\" "
                "must NOT carry a `sumf` scalar accumulator in the yield (the "
                "no-min fold uses only the `sums` vector; a dual yield here is "
                "rejected)";
    return mlir::success();
  }

  // W-A (q2_K milestone-1): fold_model KEYS the accumulator arity. The q2_K
  // "scalar_scale_min" path carries a SCALAR accumulator: exactly TWO region
  // entry arguments (the super_block_index induction variable + the loop-carried
  // `sumf` SCALAR f32 accumulator) and a yield naming the `sumf` scalar ALONE (no
  // 8-lane `sums` vector -- q2_K's positive fold is the single per-super-block
  // scalar `dall*isum`, NOT a deferred 8-lane vector, so there is no vector
  // accumulator). An 8-lane vector first accumulator, or a second (`sumf_next`)
  // yield operand under this scalar fold, is rejected fail-closed. The q4_K/q5_K
  // dual and q6_K single-vector paths are unchanged.
  if (getFoldModel() == "scalar_scale_min") {
    mlir::Block &block = getBody().front();
    if (block.getNumArguments() != 2)
      return emitOpError()
             << "requires the region to carry exactly two entry arguments for "
                "the scalar-accumulator q2_K fold_model \"scalar_scale_min\": "
                "the super_block_index induction variable and the loop-carried "
                "`sumf` SCALAR f32 accumulator (an 8-lane vector `sums` "
                "accumulator is rejected under the scalar fold)";
    if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
      return emitOpError()
             << "requires the first region argument (super_block_index) to be "
                "index-typed (the nb super-block induction variable)";
    if (!block.getArgument(1).getType().isF32())
      return emitOpError()
             << "requires the second region argument (the loop-carried `sumf` "
                "accumulator) to be scalar f32 (the q2_K scalar positive+min "
                "fold; an 8-lane vector `sums` accumulator is rejected under "
                "\"scalar_scale_min\")";
    TypedSuperBlockBlockDotLoopYieldOp yield =
        block.empty()
            ? TypedSuperBlockBlockDotLoopYieldOp()
            : llvm::dyn_cast<TypedSuperBlockBlockDotLoopYieldOp>(&block.back());
    if (!yield)
      return emitOpError()
             << "requires the region to be terminated by "
                "weft_rvv.typed_super_block_block_dot_loop_yield (the single "
                "carried-out `sumf` scalar accumulator)";
    if (!yield.getSumsNext().getType().isF32())
      return emitOpError()
             << "requires the loop yield to carry the scalar f32 `sumf` "
                "accumulator as its (single) first operand under the scalar "
                "fold_model \"scalar_scale_min\" (an 8-lane vector is rejected)";
    if (yield.getSumfNext())
      return emitOpError()
             << "the scalar-accumulator q2_K fold_model \"scalar_scale_min\" "
                "must NOT carry a second `sumf_next` operand in the yield (the "
                "scalar path carries a single f32 accumulator; a dual yield here "
                "is rejected)";
    return mlir::success();
  }

  // W-A (iq1_s milestone-1): fold_model KEYS the accumulator arity. The iq1_s
  // "scalar_delta_grid" path carries a SCALAR accumulator arity-IDENTICAL to
  // q2_K's "scalar_scale_min": exactly TWO region entry arguments (the
  // super_block_index induction variable + the loop-carried `sumf` SCALAR f32
  // accumulator) and a yield naming the `sumf` scalar ALONE. The STRUCTURAL
  // contrast with q2_K is the fold ARITHMETIC (iq1_s's `sumf += d*((float)sumi +
  // IQ1S_DELTA*(float)sumi1)` ternary-grid delta fold, keyed for the milestone-2
  // emitter) and the in-region brick (the ternary-grid integer core
  // weft_rvv.iq1_s_q8_k_grid_core, decode_model=lookup, vs q2_K's arithmetic
  // integer core); the accumulator arity is the same single f32 scalar, so the
  // region/yield contract mirrors the scalar path. An 8-lane vector first
  // accumulator, or a second (`sumf_next`) yield operand under this scalar fold,
  // is rejected fail-closed. The q4_K/q5_K dual, q6_K single-vector, and q2_K
  // scalar paths are unchanged (additive; zero regression).
  if (getFoldModel() == "scalar_delta_grid") {
    mlir::Block &block = getBody().front();
    if (block.getNumArguments() != 2)
      return emitOpError()
             << "requires the region to carry exactly two entry arguments for "
                "the scalar-accumulator iq1_s fold_model \"scalar_delta_grid\": "
                "the super_block_index induction variable and the loop-carried "
                "`sumf` SCALAR f32 accumulator (an 8-lane vector `sums` "
                "accumulator is rejected under the scalar fold)";
    if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
      return emitOpError()
             << "requires the first region argument (super_block_index) to be "
                "index-typed (the nb super-block induction variable)";
    if (!block.getArgument(1).getType().isF32())
      return emitOpError()
             << "requires the second region argument (the loop-carried `sumf` "
                "accumulator) to be scalar f32 (the iq1_s scalar ternary-grid "
                "delta fold; an 8-lane vector `sums` accumulator is rejected "
                "under \"scalar_delta_grid\")";
    TypedSuperBlockBlockDotLoopYieldOp yield =
        block.empty()
            ? TypedSuperBlockBlockDotLoopYieldOp()
            : llvm::dyn_cast<TypedSuperBlockBlockDotLoopYieldOp>(&block.back());
    if (!yield)
      return emitOpError()
             << "requires the region to be terminated by "
                "weft_rvv.typed_super_block_block_dot_loop_yield (the single "
                "carried-out `sumf` scalar accumulator)";
    if (!yield.getSumsNext().getType().isF32())
      return emitOpError()
             << "requires the loop yield to carry the scalar f32 `sumf` "
                "accumulator as its (single) first operand under the scalar "
                "fold_model \"scalar_delta_grid\" (an 8-lane vector is rejected)";
    if (yield.getSumfNext())
      return emitOpError()
             << "the scalar-accumulator iq1_s fold_model \"scalar_delta_grid\" "
                "must NOT carry a second `sumf_next` operand in the yield (the "
                "scalar path carries a single f32 accumulator; a dual yield here "
                "is rejected)";
    return mlir::success();
  }

  // Region structure: exactly THREE entry arguments -- the super_block_index
  // induction variable (index), the loop-carried `sums` 8-lane fp32 vector
  // accumulator, and the loop-carried `sumf` scalar f32 accumulator -- terminated
  // by the typed super-block loop yield naming BOTH carried-out accumulators. A
  // single accumulator / wrong arg count is rejected fail-closed (this is the
  // dual-accumulator contrast against the flat single-f32 loop op).
  mlir::Block &block = getBody().front();
  if (block.getNumArguments() != 3)
    return emitOpError()
           << "requires the region to carry exactly three entry arguments: the "
              "super_block_index induction variable, the loop-carried `sums` "
              "8-lane fp32 vector accumulator, and the loop-carried `sumf` "
              "scalar f32 accumulator (the DUAL accumulator; a single-accumulator "
              "region is rejected)";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (super_block_index) to be "
              "index-typed (the nb super-block induction variable)";
  if (!isF32M2VectorAccumulator(block.getArgument(1).getType()))
    return emitOpError()
           << "requires the second region argument (the loop-carried `sums` "
              "accumulator) to be an 8-lane fp32 vector "
              "(!weft_rvv.vector<f32, \"m2\">)";
  if (!block.getArgument(2).getType().isF32())
    return emitOpError()
           << "requires the third region argument (the loop-carried `sumf` "
              "accumulator) to be scalar f32";

  TypedSuperBlockBlockDotLoopYieldOp yield =
      block.empty()
          ? TypedSuperBlockBlockDotLoopYieldOp()
          : llvm::dyn_cast<TypedSuperBlockBlockDotLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_super_block_block_dot_loop_yield (the DUAL "
              "carried-out `sums` vector + `sumf` scalar accumulators)";
  if (!isF32M2VectorAccumulator(yield.getSumsNext().getType()))
    return emitOpError()
           << "requires the loop yield to carry an 8-lane fp32 vector `sums` "
              "accumulator (!weft_rvv.vector<f32, \"m2\">) as its first operand";
  // fold_model-keyed arity: the DUAL fold requires the yield to name the `sumf`
  // scalar (the sumf operand is now ODS-optional to support the q6_K single path,
  // so a dual body with a sumf-absent single yield is rejected fail-closed here).
  if (!yield.getSumfNext())
    return emitOpError()
           << "the dual fold_model \"super_block_two_level_scale_min\" requires "
              "the loop yield to name the `sumf` scalar accumulator (a single, "
              "sumf-absent yield is rejected under the dual fold)";
  if (!yield.getSumfNext().getType().isF32())
    return emitOpError()
           << "requires the loop yield to carry a scalar f32 `sumf` accumulator "
              "as its second operand";

  return mlir::success();
}

mlir::LogicalResult TypedSuperBlockBlockDotLoopYieldOp::verify() {
  // Structural fail-closed (I7): the first carried-out operand is EITHER the
  // 8-lane fp32 vector `sums` chain (q4_K/q5_K/q6_K) OR a scalar f32 `sumf` chain
  // (q2_K's scalar fold). The second `sumf` scalar operand is OPTIONAL (present =
  // the q4_K/q5_K dual MIN-term chain; absent = the q6_K/q2_K single path); when
  // present it must be scalar f32 (so a q4_K/q5_K swapped vector-second pair is
  // rejected by this check). The fold_model-keyed arity match (which fold carries
  // which first-operand shape and whether a second sumf operand is allowed) is
  // enforced by the parent loop body verifier, which runs BEFORE this nested
  // yield verifier.
  mlir::Type sumsNextTy = getSumsNext().getType();
  if (!isF32M2VectorAccumulator(sumsNextTy) && !sumsNextTy.isF32())
    return emitOpError()
           << "requires the first carried-out accumulator to be either an "
              "8-lane fp32 vector `sums` accumulator (!weft_rvv.vector<f32, "
              "\"m2\">, the q4_K/q5_K/q6_K positive-fold chain) or a scalar f32 "
              "`sumf` accumulator (the q2_K scalar fold chain)";
  if (getSumfNext() && !getSumfNext().getType().isF32())
    return emitOpError()
           << "requires the second carried-out accumulator, when present, to be "
              "scalar f32 (the block-carried `sumf` MIN-term accumulator domain)";
  return mlir::success();
}

mlir::LogicalResult TypedRepackGemvLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded surface (I7 fail-closed): the repack GEVM loop op owns the q4_0
  // 16x1-repacked per-strip lane-wise fold tree; any other kind/fold_model/
  // scale_model spelling is rejected fail-closed.
  if (getKind() != "typed_repack_gemv_loop_body")
    return emitOpError()
           << "currently supports only kind \"typed_repack_gemv_loop_body\" for "
              "the bounded q4_0 16x1-repacked GEVM block loop surface";
  // Four bounded repacked GEVM fold trees: the q4_0 dual-fp16 per-strip lane-wise
  // fold ("lane_wise_vector_scale"), the TERNARY single-fp16 no-min fold
  // ("ternary_single_fp16_scale", the front-door construction of the retired
  // emitRepackGemvTQ{20,10}Q8K direct emitter), the K-QUANT q4_K dual d/dmin +
  // bsums-min fold ("kquant_dmin_bsums_min", the front-door construction of the
  // retired emitRepackGemvQ4KQ8K direct emitter), and the K-QUANT q6_K SINGLE-scale
  // no-min fold ("kquant_single_scale_no_min", the front-door construction of the
  // retired emitRepackGemvQ6KQ8K direct emitter). The ternary path disambiguates
  // tq2_0/tq1_0 by the in-region repack_gemv_ternary_core brick's decode_model; the
  // K-quant path carries the repack_gemv_kquant_core brick (decode_model "q4_K" for
  // the min fold, "q6_K" for the no-min fold).
  bool isTernaryFold = getFoldModel() == "ternary_single_fp16_scale";
  bool isKQuantQ4KFold = getFoldModel() == "kquant_dmin_bsums_min";
  bool isKQuantQ6KFold = getFoldModel() == "kquant_single_scale_no_min";
  bool isKQuantFold = isKQuantQ4KFold || isKQuantQ6KFold;
  bool isCodebookFlatFold = getFoldModel() == "codebook_flat_single_scale";
  // The iq4_xs SUPER-BLOCK codebook fold: the SAME memory-gather codebook decode as the
  // iq4_nl flat fold, PLUS a K-quant-style 6-bit SIGNED per-sub-block scale (scales_l LOW
  // pair + scales_h HIGH 2-bit, biased -32, NO min) folded via i32 vmacc. It rides the
  // SHARED codebook core brick (decode_model "iq4_xs") and carries the OPTIONAL super-block
  // scale attrs (weight_scales_byte_offset / weight_scales_high_byte_offset / n_subblocks).
  bool isCodebookSuperblockFold =
      getFoldModel() == "codebook_superblock_signed6_no_min";
  // The mxfp4 FLAT codebook fold WITH the E8M0 shared-exponent per-column scale (the
  // E8M0 sibling of the iq4_nl flat single-fp16-scale fold): the SAME memory-gather
  // codebook decode + i32 dot, but the single fp16 scale is replaced by the E8M0
  // 2^(e-128) bit-construction. It rides the SHARED codebook core brick (decode_model
  // "mxfp4") and carries NO super-block scale attrs (it is a FLAT fold, nSubblocks == 0).
  bool isCodebookE8m0Fold = getFoldModel() == "codebook_flat_e8m0_scale";
  bool isCodebookFold =
      isCodebookFlatFold || isCodebookSuperblockFold || isCodebookE8m0Fold;
  // The iq2_xxs GRID CODEBOOK + SIGN-PLANE single ls-scale fold (the FIRST grid decode
  // family, retirement_batch 3): the SAME per-strip lane-wise fp16*fp32 no-min fold as the
  // codebook flat fold PLUS the 0.125 (1/8) trailing factor and the per-sub-block int8 ls
  // scale (i32 vmacc). It rides the NEW repack_gem{v,m}_grid_core brick (decode_model
  // "iq2_xxs"), which carries the grid/ls/sign byte offsets + n_subblocks; the FIXED grid
  // + signs64 planes are DERIVED static const tables (NEVER op attrs).
  // The iq1_s TERNARY-DELTA grid fold (C4a-2): SINGLE ls, NO sign plane (the grid
  // bytes are already signed ternary) and a per-sub-block +-1 delta (qh bit15)
  // riding the sign-plane offset slot as a DELTA strip. Its fold is the ONLY grid
  // fold that reads the activation bsums: sumf += d*(sumi + 0.125f*sumi1).
  bool isGridDeltaFold = getFoldModel() == "grid_ternary_delta_eighth";
  // The iq1_m TERNARY-DELTA GROUP-SUM grid fold (C4a-3): iq1_s's sibling -- same
  // already-signed ternary grid and same sumf += d*(accA + 0.125f*accB) expression, but
  // DUAL ls, a PER-GROUP-of-8 +-1 delta (four INDEPENDENT bits per sub-block), and a
  // delta term built from IN-KERNEL group-of-8 activation sums. It is deliberately kept
  // OUT of isGridDeltaFold: that bool is what admits activation_bsums_byte_offset, and
  // iq1_m must NOT be able to stamp one -- block_q8_K's bsums are sums over groups of
  // SIXTEEN, so they cannot express iq1_m's per-8 group sum (the two 8-groups inside one
  // bsums entry carry independent delta signs). An iq1_m loop body carrying a bsums
  // offset is therefore REJECTED here, which is the fail-closed reading of "iq1_m does
  // not read bsums".
  bool isGridGroupSumFold =
      getFoldModel() == "grid_ternary_delta_groupsum_eighth";
  // The iq3_xxs DUAL-ENTRY grid fold (C4a-4): the SAME single-accumulator
  // sign-plane-gathering shape as "grid_sign_single_scale_eighth", differing in the two
  // ways ggml_vec_dot_iq3_xxs_q8_K differs from its iq2_xxs sibling -- TWO grid entries
  // per 8-lane group (a uint32 entry covers only half a group) and a 0.25f rather than
  // 0.125f store constant. It gets its own fold_model rather than riding iq2_xxs's
  // because it needs its own emitter leaf: nothing about "single scale" distinguishes
  // them, and a fold_model that admitted both would be a name for two different nests.
  // C4a-5: iq3_s joins this fold. It is the SAME dual-entry nest (a uint32 entry covers
  // half a group, so two bases per group with the activation range split) and the SAME
  // single accumulator; the two fold_models are distinct because their STORE constants
  // are (0.25f vs ggml iq3_s's `*s = sumf`), and a fold_model naming a constant it does
  // not apply is the mislabel this family already shipped twice.
  bool isGridDualEntryFold =
      getFoldModel() == "grid_sign_dual_entry_single_scale_quarter" ||
      getFoldModel() == "grid_sign_dual_entry_single_scale_unit";
  bool isGridFold = getFoldModel() == "grid_sign_single_scale_eighth" ||
                    getFoldModel() == "grid_sign_dualscale_eighth" ||
                    isGridDeltaFold || isGridGroupSumFold || isGridDualEntryFold;
  // The q4_1 UNSIGNED-nibble dual-fp16 + single MIN fold: the SAME per-strip
  // lane-wise vfwmul/vfcvt/vfmacc scale tree as q4_0 PLUS the lane-wise `acc +=
  // m_x*s_y` min correction. It rides the SHARED q4_0 core + fold bricks (the core
  // stamps weight_nibble_unsigned; the fold stamps the min-fold offset pair), so it
  // falls through to the SAME emitter default path as q4_0.
  bool isNibbleMinFold = getFoldModel() == "lane_wise_vector_scale_min";
  if (getFoldModel() != "lane_wise_vector_scale" && !isNibbleMinFold &&
      !isTernaryFold && !isKQuantFold && !isCodebookFold && !isGridFold)
    return emitOpError()
           << "currently supports only fold_model \"lane_wise_vector_scale\" (the "
              "q4_0 repacked GEVM per-strip vfwmul/vfcvt/vfmacc lane-wise fold "
              "tree), \"lane_wise_vector_scale_min\" (the q4_1 unsigned-nibble "
              "dual-fp16 + single MIN fold), \"ternary_single_fp16_scale\" (the "
              "ternary single-scale no-min fold), \"kquant_dmin_bsums_min\" (the "
              "K-quant q4_K dual d/dmin + bsums-min fold), or "
              "\"kquant_single_scale_no_min\" (the K-quant q6_K 6-bit two-plane "
              "single-accumulator no-min fold), or "
              "\"codebook_flat_single_scale\" (the iq4_nl flat non-linear "
              "16-entry codebook single-scale fold), or "
              "\"codebook_superblock_signed6_no_min\" (the iq4_xs super-block "
              "16-entry codebook + 6-bit signed sub-block-scale fold), or "
              "\"codebook_flat_e8m0_scale\" (the mxfp4 flat 16-entry doubled-e2m1 "
              "codebook + E8M0 shared-exponent scale fold), or "
              "\"grid_sign_single_scale_eighth\" (the iq2_xxs grid + sign-plane "
              "single ls-scale 0.125 fold), or "
              "\"grid_sign_dualscale_eighth\" (the iq2_xs / iq2_s grid + sign-plane "
              "dual ls-scale 0.125 fold), or "
              "\"grid_ternary_delta_eighth\" (the iq1_s signed-ternary grid + "
              "per-sub-block +-1 delta-bsum dual-accumulator 0.125 fold), or "
              "\"grid_ternary_delta_groupsum_eighth\" (the iq1_m signed-ternary grid "
              "+ dual ls + per-GROUP +-1 delta with IN-KERNEL group-of-8 activation "
              "sums dual-accumulator 0.125 fold), or "
              "\"grid_sign_dual_entry_single_scale_quarter\" (the iq3_xxs grid + "
              "sign-plane single ls-scale fold with TWO uint32 grid entries per "
              "8-element group and a 0.25 store), or "
              "\"grid_sign_dual_entry_single_scale_unit\" (the iq3_s explicit-sign "
              "grid + the SAME dual-entry nest and single ls-scale, with NO store "
              "constant at all)";
  if (!isTernaryFold && !isKQuantFold && !isCodebookFold && !isGridFold &&
      getScaleModel() != "dual-fp16-per-block-d_x.d_y" &&
      getScaleModel() != "dual-fp16-per-block-d_x.d_y-plus-min")
    return emitOpError()
           << "currently supports only scale_model "
              "\"dual-fp16-per-block-d_x.d_y\" (the q4_0 per-block d_x*d_y "
              "dual-fp16 repacked scale model) or "
              "\"dual-fp16-per-block-d_x.d_y-plus-min\" (the q4_1 dual-fp16 + "
              "single min scale model)";

  // The OPTIONAL SECOND weight-plane (qh) byte offset (I7): the ternary tq1_0 base-3
  // qh plane, the q6_K high-2-bit / q3_K hmask high-bit no-min qh plane, OR the q5_K
  // 5th-bit qh plane on the MIN fold. Valid under the ternary fold OR EITHER K-quant
  // fold (q5_K carries qh on the "kquant_dmin_bsums_min" min fold; q6_K/q3_K carry it
  // on the "kquant_single_scale_no_min" no-min fold). The bare q4_0 nibble fold and the
  // qh-less q4_K/q2_K min families simply do not stamp it. When present it must be a
  // positive within-block byte count.
  if (mlir::IntegerAttr qhAttr = getWeightQhByteOffsetAttr()) {
    if (!isTernaryFold && !isKQuantFold)
      return emitOpError()
             << "does not accept weight_qh_byte_offset outside the ternary "
                "single-fp16 fold (the base-3 qh SECOND weight-plane) or a K-quant "
                "fold (the q6_K/q3_K no-min high-bit plane or the q5_K min-fold "
                "5th-bit plane)";
    if (qhAttr.getInt() <= 0)
      return emitOpError()
             << "requires weight_qh_byte_offset > 0 (the qh SECOND weight-plane "
                "byte offset); got "
             << qhAttr.getInt();
  }

  // Main-term form is a final construction field, not an emitter option.  Its
  // applicability follows the typed fold vocabulary; the verifier checks only
  // presence and the closed value set and does not replay the schedule formula.
  if (isKQuantFold) {
    if (!getMainTermForm())
      return emitOpError()
             << "requires main_term_form for a K-quant fold; the construction "
                "stage must choose \"unrolled\" or \"rolled\"";
    llvm::StringRef form = *getMainTermForm();
    if (form != "unrolled" && form != "rolled")
      return emitOpError()
             << "only accepts main_term_form \"unrolled\" or \"rolled\"; got \""
             << form << "\"";
  } else if (getMainTermForm()) {
    return emitOpError()
           << "does not accept main_term_form outside the K-quant fold models";
  }

  // The OPTIONAL K-quant super-block decode facts (I7). The 6-bit/signed scales
  // region offset + the sub-block count ride on EITHER K-quant fold (q4_K or q6_K).
  // The per-column dmin strip offset + the activation int16 bsums offset are the
  // q4_K MIN structure and are valid ONLY under the q4_K "kquant_dmin_bsums_min"
  // fold (q6_K is single-accumulator no-min). Each, when present, must be a positive
  // byte count / count (read the SIGNED attr view). ABSENT for q4_0 / ternary.
  {
    auto kq = [&](mlir::IntegerAttr a, llvm::StringRef name,
                  bool valid) -> mlir::LogicalResult {
      if (!a)
        return mlir::success();
      if (!valid)
        return emitOpError()
               << "does not accept " << name
               << " for this fold_model (a super-block decode fact is legal ONLY "
                  "under the folds that READ it: the min-structure facts under the "
                  "q4_K \"kquant_dmin_bsums_min\" fold, and -- for "
                  "activation_bsums_byte_offset ONLY -- also the iq1_s "
                  "\"grid_ternary_delta_eighth\" delta fold)";
      if (a.getInt() <= 0)
        return emitOpError() << "requires " << name
                             << " > 0 (a K-quant super-block byte offset / "
                                "count); got "
                             << a.getInt();
      return mlir::success();
    };
    // weight_scales_byte_offset (the packed scales region: K-quant 6-bit scales/mins OR
    // the iq4_xs scales_l LOW pair) + n_subblocks ride on EITHER a K-quant fold OR the
    // iq4_xs codebook super-block fold. The iq4_xs scales_h HIGH 2-bit region rides ONLY
    // on the codebook super-block fold. The dmin strip + activation bsums are the q4_K
    // MIN structure (q4_K min fold only). ABSENT for q4_0 / ternary / flat codebook.
    if (mlir::failed(kq(getWeightDminByteOffsetAttr(),
                        "weight_dmin_byte_offset", isKQuantQ4KFold)) ||
        mlir::failed(kq(getWeightScalesByteOffsetAttr(),
                        "weight_scales_byte_offset",
                        isKQuantFold || isCodebookSuperblockFold)) ||
        mlir::failed(kq(getWeightScalesHighByteOffsetAttr(),
                        "weight_scales_high_byte_offset",
                        isCodebookSuperblockFold)) ||
        // The activation int16 bsums are read by EXACTLY TWO folds: the q4_K
        // min-structure fold (the -dmin*min_sb*bsum correction) and the iq1_s
        // ternary-delta grid fold (the ls*delta*bsum-pair sumi1 term). Every
        // OTHER fold still REJECTS the attr ([D-1] unknown = reject is widened by
        // exactly one NAMED fold, not opened).
        mlir::failed(kq(getActivationBsumsByteOffsetAttr(),
                        "activation_bsums_byte_offset",
                        isKQuantQ4KFold || isGridDeltaFold)) ||
        mlir::failed(kq(getNSubblocksAttr(), "n_subblocks",
                        isKQuantFold || isCodebookSuperblockFold)))
      return mlir::failure();
  }

  // Externally-defined ggml repacked block facts: QK and the AoS strides are
  // positive byte counts the per-block address arithmetic depends on. Read the
  // SIGNED attr view (getXAttr().getInt()): the uint64_t ODS accessors
  // zero-extend the i64 attr, so a negative value would fail-OPEN the `<= 0`
  // guard (I7).
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0 (the QK block element count); got "
                         << getQkAttr().getInt();
  if (getWeightBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_block_stride > 0 (the block_q4_0x16 repacked "
              "weight block stride); got "
           << getWeightBlockStrideAttr().getInt();
  if (getActivationBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires activation_block_stride > 0 (the plain block_q8_0 "
              "activation block stride); got "
           << getActivationBlockStrideAttr().getInt();
  if (getWeightInterleaveAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_interleave > 0 (the block-as-lane interleave "
              "width, 16 for block_q4_0x16); got "
           << getWeightInterleaveAttr().getInt();
  // Resource-aware strip width (I7): half_lanes must be in {8, 16} and divide the
  // 16-way interleave, exactly as the monolithic repack GEVM op pins it.
  int64_t half = getHalfLanes();
  if ((half != 8 && half != 16) || getWeightInterleave() % half != 0)
    return emitOpError()
           << "requires half_lanes in {8, 16} dividing weight_interleave (the "
              "resource-aware e16m1 strip width); got "
           << half;

  // Bounded scheduling knob (the *how*, never the *what*): the integer-core
  // widening-chain base LMUL {"mf2" (RVV1.0 fractional), "m1" (RVV0.7 whole)}.
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul()) {
    if (*coreLmul != "mf2" && *coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 fractional "
                "chain) or \"m1\" (the RVV0.7 whole-LMUL chain); got \""
             << *coreLmul << "\"";
  }

  if (op->getNumOperands() != 5 || op->getNumResults() != 0)
    return emitOpError()
           << "requires the five repacked-GEVM ABI operands (weight base, "
              "activation base, output, element count, column count) and no "
              "results (the lane-wise vector store is the sink)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of C "
              "type 'const uint8_t *' (the block_q4_0x16 repacked weight byte "
              "array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI value "
              "of C type 'const uint8_t *' (the plain block_q8_0 activation byte "
              "array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml *s destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be the runtime nc index "
              "value driving the weight-column-group loop";

  // The disjoint-strip count: numHalves == weight_interleave / half_lanes (1 for
  // the 16-lane one-strip VLEN=256/RVV0.7 form, 2 for the two-8-lane-halves
  // VLEN=128 form). The region carries ONE accumulator per strip.
  int64_t numHalves = getWeightInterleave() / half;

  // Region: numHalves + 1 entry args -- the block_index induction variable
  // FOLLOWED by the numHalves loop-carried per-strip f32 VECTOR accumulators --
  // terminated by the repack loop yield naming the carried-out vectors (the
  // lane-wise VECTOR contrast against the flat loop op's scalar accumulator).
  mlir::Block &block = getBody().front();
  if (block.getNumArguments() != numHalves + 1)
    return emitOpError()
           << "requires the region to carry exactly numHalves + 1 ("
           << (numHalves + 1)
           << ") entry arguments: the block_index induction variable and the "
              "numHalves loop-carried per-strip f32 vector accumulators";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (block_index) to be "
              "index-typed (the nb block induction variable)";
  for (int64_t h = 0; h < numHalves; ++h) {
    if (!isF32M2OrM4VectorAccumulator(block.getArgument(1 + h).getType()))
      return emitOpError()
             << "requires each per-strip loop-carried accumulator region argument "
                "to be an f32 vector (!weft_rvv.vector<f32, \"m2\"> or "
                "<f32, \"m4\">)";
    if (block.getArgument(1 + h).getType() != block.getArgument(1).getType())
      return emitOpError()
             << "requires all per-strip accumulator region arguments to share "
                "the ONE f32 LMUL rung (all f32m2 or all f32m4)";
  }

  TypedRepackGemvLoopYieldOp yield =
      block.empty()
          ? TypedRepackGemvLoopYieldOp()
          : llvm::dyn_cast<TypedRepackGemvLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_repack_gemv_loop_yield (the carried-out per-strip "
              "f32 vector accumulators)";
  if (static_cast<int64_t>(yield.getAccNext().size()) != numHalves)
    return emitOpError()
           << "requires the loop yield to carry numHalves (" << numHalves
           << ") per-strip f32 vector accumulators";
  for (mlir::Value accNext : yield.getAccNext())
    if (!isF32M2OrM4VectorAccumulator(accNext.getType()))
      return emitOpError()
             << "requires each loop-yield accumulator to be a per-strip f32 "
                "vector (!weft_rvv.vector<f32, \"m2\"> or <f32, \"m4\">)";

  return mlir::success();
}

mlir::LogicalResult TypedRepackGemvLoopYieldOp::verify() {
  if (getAccNext().empty())
    return emitOpError()
           << "requires at least one carried-out per-strip f32 vector accumulator";
  for (mlir::Value accNext : getAccNext())
    if (!isF32M2OrM4VectorAccumulator(accNext.getType()))
      return emitOpError()
             << "requires every carried-out accumulator to be a per-strip f32 "
                "vector (!weft_rvv.vector<f32, \"m2\"> or <f32, \"m4\">, the "
                "lane-wise repacked GEVM accumulator domain)";
  return mlir::success();
}

mlir::LogicalResult TypedRepackGemvColgroupTiledLoopBodyOp::verify() {
  // Bounded surface (I7 fail-closed): the INDEPENDENT q4_K colgroup-tiled GEVM
  // Emission Plan ([K-10] structural-level). First cell = q4_K@rvv; the bounded
  // fold is the K-quant q4_K dual d/dmin + bsums-min fold.
  if (getKind() != "typed_repack_gemv_colgroup_tiled_loop_body")
    return emitOpError() << "currently supports only kind "
                            "\"typed_repack_gemv_colgroup_tiled_loop_body\"";
  if (getFoldModel() != "kquant_dmin_bsums_min")
    return emitOpError()
           << "currently supports only fold_model \"kquant_dmin_bsums_min\" (the "
              "q4_K dual d/dmin + bsums-min fold; the first cell of this plan)";
  // The DISTINGUISHING structural fact: column_group_tile (TG) >= 1.
  if (getColumnGroupTile() < 1)
    return emitOpError() << "requires column_group_tile >= 1 (the number of "
                            "weight-column-groups per tile); got "
                         << getColumnGroupTile();
  // The q4_K super-block MIN structure requires ALL four K-quant decode facts
  // (fail-closed, I7): dmin strip / 6-bit scales region / activation bsums / n_sub.
  if (!getWeightDminByteOffset() || !getWeightScalesByteOffset() ||
      !getActivationBsumsByteOffset() || !getNSubblocks())
    return emitOpError()
           << "the q4_K colgroup-tiled GEVM plan requires the super-block decode "
              "attrs weight_dmin_byte_offset / weight_scales_byte_offset / "
              "activation_bsums_byte_offset / n_subblocks";
  // Anti-bypass: the region MUST carry the K-quant integer-core brick
  // (decode_model "q4_K"), block_index-tied to region arg 0, named off this op's
  // own weight/activation ABI bases — the SAME structural contract as the sibling
  // GEVM plan (byte-exact-by-construction is gated on this brick's identity).
  RepackGemvKQuantCoreOp coreBrick;
  getBody().walk([&](RepackGemvKQuantCoreOp o) { coreBrick = o; });
  if (!coreBrick)
    return emitOpError()
           << "region requires the weft_rvv.repack_gemv_kquant_core integer-core "
              "brick (the anti-bypass tie of the byte-exact q4_K decode)";
  if (coreBrick.getDecodeModel() != "q4_K")
    return emitOpError() << "the colgroup-tiled GEVM plan's core brick must carry "
                            "decode_model \"q4_K\" (the first cell)";
  if (coreBrick.getBlockIndex() != getBody().front().getArgument(0))
    return emitOpError() << "the K-quant core brick's block_index must be the loop "
                            "induction variable (region arg 0)";
  if (coreBrick.getWeightBase() != getWeightBase() ||
      coreBrick.getActivationBase() != getActivationBase())
    return emitOpError()
           << "the K-quant core brick's weight/activation bases must be the loop "
              "op's own repacked-weight / q8_K-activation ABI buffers";
  return mlir::success();
}

mlir::LogicalResult RepackGemmLaneWiseQ4Q8DotOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // within-block byte offsets the per-block lane-wise nibble dot needs, and the
  // OPTIONAL integer_core_lmul resource anchor. The per-block strides, qk, the
  // interleaves, and the resource-aware strip width are the enclosing loop op's
  // facts. A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "weight_quant_byte_offset" ||
           name == "activation_quant_byte_offset" ||
           name == "integer_core_lmul" || name == "weight_nibble_unsigned" ||
           name == "weight_qh_byte_offset" || name == "weight_offset_bias" ||
           name == "weight_full_i8";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemm_lane_wise_q4_x_i8_dot keeps SEW/LMUL/"
                "policy on setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded repacked GEMM lane-wise dot attributes "
                "'kind', 'weight_quant_byte_offset', "
                "'activation_quant_byte_offset', 'integer_core_lmul', the "
                "optional q4_1 'weight_nibble_unsigned' decode selector, the "
                "optional q5_0 'weight_qh_byte_offset' / 'weight_offset_bias' "
                "5th-bit decode facts, and the optional q8_0 'weight_full_i8' "
                "full-int8 decode selector; unexpected attribute '"
             << attr.getName() << "'";
  }

  // OPTIONAL q8_0 FULL-int8 decode selector (I7): mutually exclusive with the
  // nibble decode selectors (the full-i8 core has no nibble lo/hi split, no
  // unsigned peel, no qh 5th-bit plane).
  if (getWeightFullI8()) {
    if (getWeightNibbleUnsigned() || getWeightQhByteOffsetAttr() ||
        getWeightOffsetBiasAttr())
      return emitOpError()
             << "weight_full_i8 (the q8_0 full-int8 decode) is mutually exclusive "
                "with the nibble decode selectors weight_nibble_unsigned / "
                "weight_qh_byte_offset / weight_offset_bias";
  }

  // OPTIONAL 5th-bit (qh) decode facts (I7): qh may appear WITH bias (q5_0
  // offset-binary `-16`) OR WITHOUT bias (q5_1 UNSIGNED [0,31], the asymmetric bias
  // living in the separate per-block MIN scale); a bias with NO qh is meaningless.
  // qh assembles off a RAW unsigned nibble peel, so weight_nibble_unsigned must
  // also be set; each fact, when present, must be positive.
  {
    mlir::IntegerAttr qhAttr = getWeightQhByteOffsetAttr();
    mlir::IntegerAttr biasAttr = getWeightOffsetBiasAttr();
    if (biasAttr && !qhAttr)
      return emitOpError()
             << "requires weight_offset_bias only TOGETHER with "
                "weight_qh_byte_offset (the offset-binary centering bias is "
                "meaningless without the qh 5th-bit plane)";
    if (qhAttr) {
      if (!getWeightNibbleUnsigned())
        return emitOpError()
               << "requires weight_nibble_unsigned when carrying the "
                  "weight_qh_byte_offset";
      if (qhAttr.getInt() <= 0)
        return emitOpError() << "requires weight_qh_byte_offset > 0; got "
                             << qhAttr.getInt();
      if (biasAttr && biasAttr.getInt() <= 0)
        return emitOpError() << "requires weight_offset_bias > 0; got "
                             << biasAttr.getInt();
    }
  }

  if (getKind() != "repack_gemm_lane_wise_q4_x_i8_dot")
    return emitOpError()
           << "currently supports only kind "
              "\"repack_gemm_lane_wise_q4_x_i8_dot\" for the bounded q4_0 "
              "16x1-repacked GEMM per-block one-strip N-column lane-wise "
              "nibble-dot integer-core typed surface";

  // Bounded resource knob (the *how*, never the *what*): the integer-core
  // widening-chain base LMUL {"mf2" RVV1.0 fractional, "m1" RVV0.7 whole-LMUL}.
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 fractional "
                "chain) or \"m1\" (the RVV0.7 whole-LMUL chain); got \""
             << coreLmul << "\"";
  }

  if (op->getNumOperands() != 5 || op->getNumResults() < 1)
    return emitOpError()
           << "requires the repacked weight base, the interleaved q8_0x4 "
              "activation base, one !weft_rvv.vl operand, one block_index "
              "induction operand, one strip_row_offset runtime strip operand, and "
              "one or more per-column i32 vector results (one per interleaved "
              "activation column folded in the pass -- columnsPerPass total)";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  if (!llvm::isa<mlir::IndexType>(getStripRowOffset().getType()))
    return emitOpError()
           << "requires the strip_row_offset operand to be index-typed (the "
              "enclosing runtime strip loop's h*half_lanes row offset)";
  // Each per-column combined sumi widens the i16 lo/hi accumulators one LMUL rung:
  // i32m2 for the mf2 (RVV1.0 fractional) core, i32m4 for the m1 (RVV0.7
  // whole-LMUL) core. Every column shares the ONE integer-core LMUL rung.
  for (mlir::Value result : getResults()) {
    if (!isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
        !isGenericRVVSignedOrSignlessIntegerVectorType(
            result.getType(), getRVVSEW32Bits(), getRVVLMULM4()))
      return emitOpError()
             << "requires every per-column result to be an i32 "
                "!weft_rvv.vector<i32, \"m2\"> (the mf2 core) or <i32, \"m4\"> "
                "(the m1 core) -- the per-column combined sumi";
    if (result.getType() != getResults().front().getType())
      return emitOpError()
             << "requires all per-column results to share the ONE integer-core "
                "LMUL rung (all i32m2 or all i32m4)";
  }

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked GEMM lane-wise nibble-dot integer core";

  return mlir::success();
}

mlir::LogicalResult RepackGemmDualFp16ScaleFoldOp::verify() {
  mlir::Operation *op = getOperation();

  // The op carries ONLY its bounded mirror attrs (I4): the operation kind, the
  // within-block fp16 scale byte offsets the per-column dual-fp16 fold needs, and
  // the OPTIONAL integer_core_lmul resource anchor. The per-block strides, qk, the
  // interleaves, and the resource-aware strip width are the enclosing loop op's
  // facts. A forbidden local element_count/SEW/LMUL/policy attr or an unexpected
  // name is rejected fail-closed (I7).
  auto isAllowedAttr = [](llvm::StringRef name) {
    return name == "kind" || name == "weight_scale_byte_offset" ||
           name == "activation_scale_byte_offset" ||
           name == "integer_core_lmul" || name == "weight_min_byte_offset" ||
           name == "activation_sum_byte_offset";
  };
  for (mlir::NamedAttribute attr : op->getAttrs()) {
    llvm::StringRef attrName = attr.getName().getValue();
    if (isForbiddenDataflowParameterAttr(attrName))
      return emitOpError()
             << "does not accept attribute '" << attr.getName()
             << "'; weft_rvv.repack_gemm_dual_fp16_scale_fold keeps SEW/LMUL/"
                "policy on setvl/with_vl, runtime n/AVL/VL in the surrounding "
                "control-plane IR, and rejects deleted local element_count "
                "metadata";
    if (!isAllowedAttr(attrName))
      return emitOpError()
             << "only accepts the bounded repacked GEMM per-column scale-fold "
                "attributes 'kind', 'weight_scale_byte_offset', "
                "'activation_scale_byte_offset', 'integer_core_lmul', and the "
                "optional q4_1 min-fold pair 'weight_min_byte_offset' / "
                "'activation_sum_byte_offset'; unexpected attribute '"
             << attr.getName() << "'";
  }
  // The q4_1 single MIN-fold facts are a PAIR (both present = the q4_1 GEMM fold
  // adds the per-column `acc += m_x*s_y[c]`; both absent = the q4_0 no-min fold).
  if (getWeightMinByteOffsetAttr().operator bool() !=
      getActivationSumByteOffsetAttr().operator bool())
    return emitOpError()
           << "requires the q4_1 min-fold facts weight_min_byte_offset and "
              "activation_sum_byte_offset to be present together (both) or absent "
              "together (the q4_0 no-min fold)";

  if (getKind() != "repack_gemm_dual_fp16_scale_fold")
    return emitOpError()
           << "currently supports only kind "
              "\"repack_gemm_dual_fp16_scale_fold\" for the bounded q4_0 "
              "16x1-repacked GEMM per-block per-column dual-fp16 scale fold typed "
              "surface";

  // Bounded resource knob (the *how*, never the *what*): the widening-chain base
  // LMUL {"mf2" RVV1.0 fractional f32m2 fold, "m1" RVV0.7 whole-LMUL f32m4 fold}.
  if (getIntegerCoreLmul().has_value()) {
    llvm::StringRef coreLmul = *getIntegerCoreLmul();
    if (coreLmul != "mf2" && coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 fractional "
                "f32m2 fold) or \"m1\" (the RVV0.7 whole-LMUL f32m4 fold); got \""
             << coreLmul << "\"";
  }

  if (op->getNumOperands() != 7 || op->getNumResults() != 1)
    return emitOpError()
           << "requires the repacked weight base, the interleaved q8_0x4 "
              "activation base, the per-column i32 sumi, the loop-carried "
              "per-column f32 accumulator, one !weft_rvv.vl operand, one "
              "block_index induction operand, and one strip_row_offset runtime "
              "strip operand, producing one folded-out per-column f32 vector "
              "accumulator";
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires runtime VL operand to have "
                            "!weft_rvv.vl type";
  if (!llvm::isa<mlir::IndexType>(getBlockIndex().getType()))
    return emitOpError()
           << "requires the block_index operand to be index-typed (the nb block "
              "induction variable)";
  if (!llvm::isa<mlir::IndexType>(getStripRowOffset().getType()))
    return emitOpError()
           << "requires the strip_row_offset operand to be index-typed (the "
              "enclosing runtime strip loop's h*half_lanes row offset)";
  // The consumed sumi is the integer brick's per-column combined result: i32m2 for
  // the mf2 (RVV1.0 fractional) core, i32m4 for the m1 (RVV0.7 whole-LMUL) core.
  if (!isGenericRVVSignedOrSignlessIntegerVectorType(
          getSumi().getType(), getRVVSEW32Bits(), getRVVLMULM2()) &&
      !isGenericRVVSignedOrSignlessIntegerVectorType(
          getSumi().getType(), getRVVSEW32Bits(), getRVVLMULM4()))
    return emitOpError()
           << "requires the consumed sumi to be an i32 !weft_rvv.vector<i32, "
              "\"m2\"> (the mf2 core) or <i32, \"m4\"> (the m1 core)";
  // The loop-carried accumulator + folded-out result are per-column f32 vectors:
  // f32m2 for the mf2 (RVV1.0 fractional) fold, f32m4 for the m1 (RVV0.7
  // whole-LMUL) fold. Both share the ONE fold LMUL rung, and the consumed sumi
  // must sit on that SAME rung (i32m2 <-> f32m2, i32m4 <-> f32m4).
  if (!isF32M2OrM4VectorAccumulator(getAcc().getType()))
    return emitOpError()
           << "requires the loop-carried accumulator to be a per-column f32 "
              "vector (!weft_rvv.vector<f32, \"m2\"> the mf2 fold or "
              "<f32, \"m4\"> the m1 whole-LMUL fold)";
  if (getAccNext().getType() != getAcc().getType())
    return emitOpError()
           << "requires the folded-out accumulator to share the loop-carried "
              "accumulator's f32 LMUL rung (both f32m2 or both f32m4)";
  auto accVec = llvm::cast<VectorType>(getAcc().getType());
  auto sumiVec = llvm::cast<VectorType>(getSumi().getType());
  if (sumiVec.getLmul() != accVec.getLmul())
    return emitOpError()
           << "requires the consumed sumi to sit on the same LMUL rung as the "
              "f32 accumulator (i32m2 with f32m2, i32m4 with f32m4)";

  auto withVL = verifyNestedDataflowOp(op);
  if (mlir::failed(withVL))
    return mlir::failure();
  if (mlir::failed(verifyDataflowVLOperandMatchesWithVL(op, getVl())))
    return mlir::failure();
  if (!(*withVL)->getAttrOfType<PolicyAttr>(kPolicyAttrName))
    return emitOpError()
           << "requires enclosing weft_rvv.with_vl to carry explicit policy "
              "metadata for the repacked GEMM per-column dual-fp16 scale fold";

  return mlir::success();
}

mlir::LogicalResult TypedRepackGemmLoopBodyOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded surface (I7 fail-closed): the repack GEMM loop op owns the q4_0
  // 16x1-repacked per-column per-strip lane-wise fold tree; any other kind/
  // fold_model/scale_model spelling is rejected fail-closed.
  if (getKind() != "typed_repack_gemm_loop_body")
    return emitOpError()
           << "currently supports only kind \"typed_repack_gemm_loop_body\" for "
              "the bounded q4_0 16x1-repacked GEMM block loop surface";
  // Four bounded repacked GEMM fold trees: the q4_0 dual-fp16 per-column lane-wise
  // fold ("lane_wise_vector_scale"), the TERNARY single-fp16 no-min fold
  // ("ternary_single_fp16_scale", the front-door construction of the retired
  // emitRepackGemmTQ{20,10}Q8K direct emitter), the K-QUANT q4_K dual d/dmin +
  // bsums-min fold ("kquant_dmin_bsums_min", the front-door construction of the
  // retired emitRepackGemmQ4KQ8K direct emitter), and the K-QUANT q6_K SINGLE-scale
  // no-min fold ("kquant_single_scale_no_min", the front-door construction of the
  // retired emitRepackGemmQ6KQ8K direct emitter). The ternary path disambiguates
  // tq2_0/tq1_0 by the in-region repack_gemm_ternary_core brick's decode_model; the
  // K-quant path carries the repack_gemm_kquant_core brick (decode_model "q4_K" for
  // the min fold, "q6_K" for the no-min fold).
  bool isTernaryFold = getFoldModel() == "ternary_single_fp16_scale";
  bool isKQuantQ4KFold = getFoldModel() == "kquant_dmin_bsums_min";
  bool isKQuantQ6KFold = getFoldModel() == "kquant_single_scale_no_min";
  bool isKQuantFold = isKQuantQ4KFold || isKQuantQ6KFold;
  bool isCodebookFlatFold = getFoldModel() == "codebook_flat_single_scale";
  // The iq4_xs SUPER-BLOCK codebook fold: the SAME memory-gather codebook decode as the
  // iq4_nl flat fold, PLUS a K-quant-style 6-bit SIGNED per-sub-block scale (scales_l LOW
  // pair + scales_h HIGH 2-bit, biased -32, NO min) folded via i32 vmacc. It rides the
  // SHARED codebook core brick (decode_model "iq4_xs") and carries the OPTIONAL super-block
  // scale attrs (weight_scales_byte_offset / weight_scales_high_byte_offset / n_subblocks).
  bool isCodebookSuperblockFold =
      getFoldModel() == "codebook_superblock_signed6_no_min";
  // The mxfp4 FLAT codebook fold WITH the E8M0 shared-exponent per-column scale (the
  // E8M0 sibling of the iq4_nl flat single-fp16-scale fold): the SAME memory-gather
  // codebook decode + i32 dot, but the single fp16 scale is replaced by the E8M0
  // 2^(e-128) bit-construction. It rides the SHARED codebook core brick (decode_model
  // "mxfp4") and carries NO super-block scale attrs (it is a FLAT fold, nSubblocks == 0).
  bool isCodebookE8m0Fold = getFoldModel() == "codebook_flat_e8m0_scale";
  bool isCodebookFold =
      isCodebookFlatFold || isCodebookSuperblockFold || isCodebookE8m0Fold;
  // The iq2_xxs GRID CODEBOOK + SIGN-PLANE single ls-scale fold (the FIRST grid decode
  // family, retirement_batch 3): the SAME per-strip lane-wise fp16*fp32 no-min fold as the
  // codebook flat fold PLUS the 0.125 (1/8) trailing factor and the per-sub-block int8 ls
  // scale (i32 vmacc). It rides the NEW repack_gem{v,m}_grid_core brick (decode_model
  // "iq2_xxs"), which carries the grid/ls/sign byte offsets + n_subblocks; the FIXED grid
  // + signs64 planes are DERIVED static const tables (NEVER op attrs).
  // The iq1_s TERNARY-DELTA grid fold (C4a-2): SINGLE ls, NO sign plane (the grid
  // bytes are already signed ternary) and a per-sub-block +-1 delta (qh bit15)
  // riding the sign-plane offset slot as a DELTA strip. Its fold is the ONLY grid
  // fold that reads the activation bsums: sumf += d*(sumi + 0.125f*sumi1).
  bool isGridDeltaFold = getFoldModel() == "grid_ternary_delta_eighth";
  // The iq1_m TERNARY-DELTA GROUP-SUM grid fold (C4a-3): iq1_s's sibling -- same
  // already-signed ternary grid and same sumf += d*(accA + 0.125f*accB) expression, but
  // DUAL ls, a PER-GROUP-of-8 +-1 delta (four INDEPENDENT bits per sub-block), and a
  // delta term built from IN-KERNEL group-of-8 activation sums. It is deliberately kept
  // OUT of isGridDeltaFold: that bool is what admits activation_bsums_byte_offset, and
  // iq1_m must NOT be able to stamp one -- block_q8_K's bsums are sums over groups of
  // SIXTEEN, so they cannot express iq1_m's per-8 group sum (the two 8-groups inside one
  // bsums entry carry independent delta signs). An iq1_m loop body carrying a bsums
  // offset is therefore REJECTED here, which is the fail-closed reading of "iq1_m does
  // not read bsums".
  bool isGridGroupSumFold =
      getFoldModel() == "grid_ternary_delta_groupsum_eighth";
  // The iq3_xxs DUAL-ENTRY grid fold (C4a-4): the SAME single-accumulator
  // sign-plane-gathering shape as "grid_sign_single_scale_eighth", differing in the two
  // ways ggml_vec_dot_iq3_xxs_q8_K differs from its iq2_xxs sibling -- TWO grid entries
  // per 8-lane group (a uint32 entry covers only half a group) and a 0.25f rather than
  // 0.125f store constant. It gets its own fold_model rather than riding iq2_xxs's
  // because it needs its own emitter leaf: nothing about "single scale" distinguishes
  // them, and a fold_model that admitted both would be a name for two different nests.
  // C4a-5: iq3_s joins this fold. It is the SAME dual-entry nest (a uint32 entry covers
  // half a group, so two bases per group with the activation range split) and the SAME
  // single accumulator; the two fold_models are distinct because their STORE constants
  // are (0.25f vs ggml iq3_s's `*s = sumf`), and a fold_model naming a constant it does
  // not apply is the mislabel this family already shipped twice.
  bool isGridDualEntryFold =
      getFoldModel() == "grid_sign_dual_entry_single_scale_quarter" ||
      getFoldModel() == "grid_sign_dual_entry_single_scale_unit";
  bool isGridFold = getFoldModel() == "grid_sign_single_scale_eighth" ||
                    getFoldModel() == "grid_sign_dualscale_eighth" ||
                    isGridDeltaFold || isGridGroupSumFold || isGridDualEntryFold;
  // The q4_1 UNSIGNED-nibble dual-fp16 + single MIN fold (the GEMM sibling of the
  // GEVM q4_1 fold): the SAME per-column lane-wise scale tree as q4_0 PLUS the
  // per-column `acc += m_x*s_y[c]` min correction, riding the SHARED q4_0 GEMM core
  // + fold bricks (core stamps weight_nibble_unsigned; fold stamps the min-offset
  // pair), so it falls through to the SAME emitter default path as q4_0.
  bool isNibbleMinFold = getFoldModel() == "lane_wise_vector_scale_min";
  if (getFoldModel() != "lane_wise_vector_scale" && !isNibbleMinFold &&
      !isTernaryFold && !isKQuantFold && !isCodebookFold && !isGridFold)
    return emitOpError()
           << "currently supports only fold_model \"lane_wise_vector_scale\" (the "
              "q4_0 repacked GEMM per-column vfwmul/vfcvt/vfmacc lane-wise fold "
              "tree), \"lane_wise_vector_scale_min\" (the q4_1 unsigned-nibble "
              "dual-fp16 + single MIN fold), \"ternary_single_fp16_scale\" (the "
              "ternary single-scale no-min fold), \"kquant_dmin_bsums_min\" (the "
              "K-quant q4_K dual d/dmin + bsums-min fold), or "
              "\"kquant_single_scale_no_min\" (the K-quant q6_K 6-bit two-plane "
              "single-accumulator no-min fold), or "
              "\"codebook_flat_single_scale\" (the iq4_nl flat non-linear "
              "16-entry codebook single-scale fold), or "
              "\"codebook_superblock_signed6_no_min\" (the iq4_xs super-block "
              "16-entry codebook + 6-bit signed sub-block-scale fold), or "
              "\"codebook_flat_e8m0_scale\" (the mxfp4 flat 16-entry doubled-e2m1 "
              "codebook + E8M0 shared-exponent scale fold), or "
              "\"grid_sign_single_scale_eighth\" (the iq2_xxs grid + sign-plane "
              "single ls-scale 0.125 fold), or "
              "\"grid_sign_dualscale_eighth\" (the iq2_xs / iq2_s grid + sign-plane "
              "dual ls-scale 0.125 fold), or "
              "\"grid_ternary_delta_eighth\" (the iq1_s signed-ternary grid + "
              "per-sub-block +-1 delta-bsum dual-accumulator 0.125 fold), or "
              "\"grid_ternary_delta_groupsum_eighth\" (the iq1_m signed-ternary grid "
              "+ dual ls + per-GROUP +-1 delta with IN-KERNEL group-of-8 activation "
              "sums dual-accumulator 0.125 fold), or "
              "\"grid_sign_dual_entry_single_scale_quarter\" (the iq3_xxs grid + "
              "sign-plane single ls-scale fold with TWO uint32 grid entries per "
              "8-element group and a 0.25 store), or "
              "\"grid_sign_dual_entry_single_scale_unit\" (the iq3_s explicit-sign "
              "grid + the SAME dual-entry nest and single ls-scale, with NO store "
              "constant at all)";
  if (!isTernaryFold && !isKQuantFold && !isCodebookFold && !isGridFold &&
      getScaleModel() != "dual-fp16-per-block-d_x.d_y" &&
      getScaleModel() != "dual-fp16-per-block-d_x.d_y-plus-min" &&
      getScaleModel() != "dual-fp16-per-block-d_x.d_y-plus-min-4col")
    return emitOpError()
           << "currently supports only scale_model "
              "\"dual-fp16-per-block-d_x.d_y\" (the q4_0 per-block d_x*d_y "
              "dual-fp16 repacked scale model) or the q4_1 "
              "\"dual-fp16-per-block-d_x.d_y-plus-min\" / "
              "\"dual-fp16-per-block-d_x.d_y-plus-min-4col\" min scale models";

  if (getLoopOrder() != "row_outer" && getLoopOrder() != "col_outer")
    return emitOpError()
           << "only accepts loop_order \"row_outer\" or \"col_outer\"; got \""
           << getLoopOrder() << "\"";

  // As in the GEVM sibling, this is only a structural check over final fields;
  // stride priors and winner lookup are owned by construction and are not replayed.
  if (isKQuantFold) {
    if (!getMainTermForm())
      return emitOpError()
             << "requires main_term_form for a K-quant fold; the construction "
                "stage must choose \"unrolled\" or \"rolled\"";
    llvm::StringRef form = *getMainTermForm();
    if (form != "unrolled" && form != "rolled")
      return emitOpError()
             << "only accepts main_term_form \"unrolled\" or \"rolled\"; got \""
             << form << "\"";
  } else if (getMainTermForm()) {
    return emitOpError()
           << "does not accept main_term_form outside the K-quant fold models";
  }

  // The OPTIONAL SECOND weight-plane (qh) byte offset (I7): the ternary tq1_0 base-3
  // qh plane, the q6_K high-2-bit / q3_K hmask high-bit no-min qh plane, OR the q5_K
  // 5th-bit qh plane on the MIN fold. Valid under the ternary fold OR EITHER K-quant
  // fold (q5_K carries qh on the "kquant_dmin_bsums_min" min fold; q6_K/q3_K carry it
  // on the "kquant_single_scale_no_min" no-min fold). The bare q4_0 nibble fold and the
  // qh-less q4_K/q2_K min families simply do not stamp it. When present it must be a
  // positive within-block byte count.
  if (mlir::IntegerAttr qhAttr = getWeightQhByteOffsetAttr()) {
    if (!isTernaryFold && !isKQuantFold)
      return emitOpError()
             << "does not accept weight_qh_byte_offset outside the ternary "
                "single-fp16 fold (the base-3 qh SECOND weight-plane) or a K-quant "
                "fold (the q6_K/q3_K no-min high-bit plane or the q5_K min-fold "
                "5th-bit plane)";
    if (qhAttr.getInt() <= 0)
      return emitOpError()
             << "requires weight_qh_byte_offset > 0 (the qh SECOND weight-plane "
                "byte offset); got "
             << qhAttr.getInt();
  }

  // The OPTIONAL K-quant super-block decode facts (I7). The 6-bit/signed scales
  // region offset + the sub-block count ride on EITHER K-quant fold (q4_K or q6_K).
  // The per-column dmin strip offset + the activation int16 bsums offset are the
  // q4_K MIN structure and are valid ONLY under the q4_K "kquant_dmin_bsums_min"
  // fold (q6_K is single-accumulator no-min). Each, when present, must be a positive
  // byte count / count (read the SIGNED attr view). ABSENT for q4_0 / ternary.
  {
    auto kq = [&](mlir::IntegerAttr a, llvm::StringRef name,
                  bool valid) -> mlir::LogicalResult {
      if (!a)
        return mlir::success();
      if (!valid)
        return emitOpError()
               << "does not accept " << name
               << " for this fold_model (a super-block decode fact is legal ONLY "
                  "under the folds that READ it: the min-structure facts under the "
                  "q4_K \"kquant_dmin_bsums_min\" fold, and -- for "
                  "activation_bsums_byte_offset ONLY -- also the iq1_s "
                  "\"grid_ternary_delta_eighth\" delta fold)";
      if (a.getInt() <= 0)
        return emitOpError() << "requires " << name
                             << " > 0 (a K-quant super-block byte offset / "
                                "count); got "
                             << a.getInt();
      return mlir::success();
    };
    // weight_scales_byte_offset (the packed scales region: K-quant 6-bit scales/mins OR
    // the iq4_xs scales_l LOW pair) + n_subblocks ride on EITHER a K-quant fold OR the
    // iq4_xs codebook super-block fold. The iq4_xs scales_h HIGH 2-bit region rides ONLY
    // on the codebook super-block fold. The dmin strip + activation bsums are the q4_K
    // MIN structure (q4_K min fold only). ABSENT for q4_0 / ternary / flat codebook.
    if (mlir::failed(kq(getWeightDminByteOffsetAttr(),
                        "weight_dmin_byte_offset", isKQuantQ4KFold)) ||
        mlir::failed(kq(getWeightScalesByteOffsetAttr(),
                        "weight_scales_byte_offset",
                        isKQuantFold || isCodebookSuperblockFold)) ||
        mlir::failed(kq(getWeightScalesHighByteOffsetAttr(),
                        "weight_scales_high_byte_offset",
                        isCodebookSuperblockFold)) ||
        // The activation int16 bsums are read by EXACTLY TWO folds: the q4_K
        // min-structure fold (the -dmin*min_sb*bsum correction) and the iq1_s
        // ternary-delta grid fold (the ls*delta*bsum-pair sumi1 term). Every
        // OTHER fold still REJECTS the attr ([D-1] unknown = reject is widened by
        // exactly one NAMED fold, not opened).
        mlir::failed(kq(getActivationBsumsByteOffsetAttr(),
                        "activation_bsums_byte_offset",
                        isKQuantQ4KFold || isGridDeltaFold)) ||
        mlir::failed(kq(getNSubblocksAttr(), "n_subblocks",
                        isKQuantFold || isCodebookSuperblockFold)))
      return mlir::failure();
  }

  // Externally-defined ggml repacked block facts: QK and the AoS strides are
  // positive byte counts the per-block address arithmetic depends on. Read the
  // SIGNED attr view (getXAttr().getInt()): the uint64_t ODS accessors
  // zero-extend the i64 attr, so a negative value would fail-OPEN the `<= 0`
  // guard (I7).
  if (getQkAttr().getInt() <= 0)
    return emitOpError() << "requires qk > 0 (the QK block element count); got "
                         << getQkAttr().getInt();
  if (getWeightBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_block_stride > 0 (the block_q4_0x16 repacked "
              "weight block stride); got "
           << getWeightBlockStrideAttr().getInt();
  if (getActivationBlockStrideAttr().getInt() <= 0)
    return emitOpError()
           << "requires activation_block_stride > 0 (the block_q8_0x4 "
              "interleaved activation block stride); got "
           << getActivationBlockStrideAttr().getInt();
  if (getWeightInterleaveAttr().getInt() <= 0)
    return emitOpError()
           << "requires weight_interleave > 0 (the block-as-lane interleave "
              "width, 16 for block_q4_0x16); got "
           << getWeightInterleaveAttr().getInt();
  if (getActivationInterleaveAttr().getInt() <= 0)
    return emitOpError()
           << "requires activation_interleave > 0 (the interleaved activation "
              "column count, 4 for block_q8_0x4); got "
           << getActivationInterleaveAttr().getInt();
  // Resource-aware strip width (I7): half_lanes must be in {8, 16} and divide the
  // 16-way interleave, exactly as the monolithic repack GEMM op pins it.
  int64_t half = getHalfLanes();
  if ((half != 8 && half != 16) || getWeightInterleave() % half != 0)
    return emitOpError()
           << "requires half_lanes in {8, 16} dividing weight_interleave (the "
              "resource-aware e16m1 strip width); got "
           << half;

  // Bounded scheduling knob (the *how*, never the *what*): the integer-core
  // widening-chain base LMUL {"mf2" (RVV1.0 fractional), "m1" (RVV0.7 whole)}.
  if (std::optional<llvm::StringRef> coreLmul = getIntegerCoreLmul()) {
    if (*coreLmul != "mf2" && *coreLmul != "m1")
      return emitOpError()
             << "only accepts integer_core_lmul \"mf2\" (the RVV1.0 fractional "
                "chain) or \"m1\" (the RVV0.7 whole-LMUL chain); got \""
             << *coreLmul << "\"";
  }

  if (op->getNumOperands() != 7 || op->getNumResults() != 0)
    return emitOpError()
           << "requires the seven repacked-GEMM ABI operands (weight base, "
              "activation base, output, element count, row count, column count, "
              "output row stride) and no results (the lane-wise vector store is "
              "the sink)";

  RuntimeABIValueOp weightBinding =
      getWeightBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp activationBinding =
      getActivationBase().getDefiningOp<RuntimeABIValueOp>();
  RuntimeABIValueOp outputBinding =
      getOutput().getDefiningOp<RuntimeABIValueOp>();
  if (!weightBinding || weightBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the weight base operand to bind a runtime ABI value of C "
              "type 'const uint8_t *' (the block_q4_0x16 repacked weight byte "
              "array)";
  if (!activationBinding || activationBinding.getCType() != "const uint8_t *")
    return emitOpError()
           << "requires the activation base operand to bind a runtime ABI value "
              "of C type 'const uint8_t *' (the block_q8_0x4 interleaved "
              "activation byte array)";
  if (!outputBinding || outputBinding.getCType() != "float *")
    return emitOpError()
           << "requires the output operand to bind a runtime ABI value of C type "
              "'float *' (the ggml *s destination)";
  if (!llvm::isa<mlir::IndexType>(getElementCount().getType()))
    return emitOpError()
           << "requires the element-count operand to be the runtime n index "
              "value feeding the enclosing setvl";
  if (!llvm::isa<mlir::IndexType>(getRowCount().getType()))
    return emitOpError()
           << "requires the row-count operand to be the runtime nr index value "
              "driving the activation-row-group loop";
  if (!llvm::isa<mlir::IndexType>(getColumnCount().getType()))
    return emitOpError()
           << "requires the column-count operand to be the runtime nc index "
              "value driving the weight-column-group loop";
  if (!llvm::isa<mlir::IndexType>(getOutputRowStride().getType()))
    return emitOpError()
           << "requires the output-row-stride operand to be the runtime bs index "
              "value (the fp32 output row stride)";

  // The per-pass fold granularity: columnsPerPass == activation_interleave for the
  // RVV1.0 fractional mf2 core (all interleaved columns folded in one pass), or 1
  // for the RVV0.7 whole-LMUL m1 core (one column per pass, the spill-avoiding
  // form). The region carries ONE accumulator per column-in-pass.
  bool isM1 = getIntegerCoreLmul().has_value() && *getIntegerCoreLmul() == "m1";
  int64_t columnsPerPass = isM1 ? 1 : getActivationInterleave();

  // Region: columnsPerPass + 2 entry args -- the block_index induction variable,
  // the runtime strip_row_offset, FOLLOWED by the columnsPerPass loop-carried
  // per-column f32 VECTOR accumulators -- terminated by the repack GEMM loop yield
  // naming the carried-out vectors.
  mlir::Block &block = getBody().front();
  if (static_cast<int64_t>(block.getNumArguments()) != columnsPerPass + 2)
    return emitOpError()
           << "requires the region to carry exactly columnsPerPass + 2 ("
           << (columnsPerPass + 2)
           << ") entry arguments: the block_index induction variable, the runtime "
              "strip_row_offset, and the columnsPerPass loop-carried per-column "
              "f32 vector accumulators";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(0).getType()))
    return emitOpError()
           << "requires the first region argument (block_index) to be "
              "index-typed (the nb block induction variable)";
  if (!llvm::isa<mlir::IndexType>(block.getArgument(1).getType()))
    return emitOpError()
           << "requires the second region argument (strip_row_offset) to be "
              "index-typed (the runtime strip loop's h*half_lanes row offset)";
  for (int64_t c = 0; c < columnsPerPass; ++c) {
    if (!isF32M2OrM4VectorAccumulator(block.getArgument(2 + c).getType()))
      return emitOpError()
             << "requires each per-column loop-carried accumulator region "
                "argument to be an f32 vector (!weft_rvv.vector<f32, \"m2\"> or "
                "<f32, \"m4\">)";
    if (block.getArgument(2 + c).getType() != block.getArgument(2).getType())
      return emitOpError()
             << "requires all per-column accumulator region arguments to share "
                "the ONE f32 LMUL rung (all f32m2 or all f32m4)";
  }

  TypedRepackGemmLoopYieldOp yield =
      block.empty()
          ? TypedRepackGemmLoopYieldOp()
          : llvm::dyn_cast<TypedRepackGemmLoopYieldOp>(&block.back());
  if (!yield)
    return emitOpError()
           << "requires the region to be terminated by "
              "weft_rvv.typed_repack_gemm_loop_yield (the carried-out per-column "
              "f32 vector accumulators)";
  if (static_cast<int64_t>(yield.getAccNext().size()) != columnsPerPass)
    return emitOpError()
           << "requires the loop yield to carry columnsPerPass (" << columnsPerPass
           << ") per-column f32 vector accumulators";
  for (mlir::Value accNext : yield.getAccNext())
    if (!isF32M2OrM4VectorAccumulator(accNext.getType()))
      return emitOpError()
             << "requires each loop-yield accumulator to be a per-column f32 "
                "vector (!weft_rvv.vector<f32, \"m2\"> or <f32, \"m4\">)";

  return mlir::success();
}

mlir::LogicalResult TypedRepackGemmLoopYieldOp::verify() {
  if (getAccNext().empty())
    return emitOpError()
           << "requires at least one carried-out per-column f32 vector "
              "accumulator";
  for (mlir::Value accNext : getAccNext())
    if (!isF32M2OrM4VectorAccumulator(accNext.getType()))
      return emitOpError()
             << "requires every carried-out accumulator to be a per-column f32 "
                "vector (!weft_rvv.vector<f32, \"m2\"> or <f32, \"m4\">, the "
                "lane-wise repacked GEMM accumulator domain)";
  return mlir::success();
}

mlir::LogicalResult TypedVectorLane0ToScalarExtractOp::verify() {
  mlir::Operation *op = getOperation();

  // Bounded surface (I7 fail-closed): the extract bridge only owns the i32m1
  // lane0 -> scalar i32 extraction; any other kind/relation spelling is
  // rejected fail-closed.
  if (getKind() != "vector_lane0_to_scalar_i32_extract")
    return emitOpError()
           << "currently supports only kind "
              "\"vector_lane0_to_scalar_i32_extract\" for the bounded i32m1 "
              "lane0 -> scalar i32 extract bridge";
  if (getExtractRelation() != "i32m1-lane0-to-scalar-i32")
    return emitOpError()
           << "currently supports only extract_relation "
              "\"i32m1-lane0-to-scalar-i32\" (the vwredsum lane0 -> scalar i32 "
              "boundary)";

  if (op->getNumOperands() != 2 || op->getNumResults() != 1)
    return emitOpError()
           << "requires one i32 LMUL m1 vector input, one !weft_rvv.vl operand, "
              "and one scalar i32 result";

  // The input is the standalone-reduce / vwredsum output shape: an i32 LMUL m1
  // vector whose lane 0 is the scalar output boundary.
  if (!isGenericRVVVectorI32M1(getInput().getType()))
    return emitOpError()
           << "requires the input to be an i32 LMUL m1 vector "
              "(!weft_rvv.vector<i32, \"m1\">) -- the vwredsum lane0 boundary";
  // The active VL token is carried as the vector boundary marker.
  if (!llvm::isa<VLType>(getVl().getType()))
    return emitOpError() << "requires the runtime VL operand to have "
                            "!weft_rvv.vl type";
  // The result is scalar i32 (the vmv_x_s extraction target); a vector result
  // (a no-op passthrough) is rejected fail-closed -- this is exactly the
  // vector -> scalar contrast the bridge exists for.
  if (!getResult().getType().isInteger(32))
    return emitOpError()
           << "requires a scalar i32 result (the lane0 vmv_x_s extraction "
              "target)";

  return mlir::success();
}
