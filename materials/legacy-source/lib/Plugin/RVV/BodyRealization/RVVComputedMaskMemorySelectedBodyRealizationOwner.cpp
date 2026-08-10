#include "Weft/Plugin/RVV/RVVComputedMaskMemorySelectedBodyRealizationOwner.h"

#include "Weft/Dialect/RVV/IR/RVVConfigContract.h"

#include "mlir/IR/Builders.h"
#include "mlir/IR/OperationSupport.h"
#include "llvm/Support/Errc.h"

#include <cstdint>
#include <utility>

namespace weft::plugin::rvv {
namespace {

constexpr llvm::StringLiteral kRVVPluginName("rvv-plugin");

llvm::Error makeRVVPluginError(llvm::Twine message) {
  return llvm::make_error<llvm::StringError>(
      llvm::Twine("Weft-RV RVV extension plugin first slice failed: ") +
          message,
      llvm::errc::invalid_argument);
}

mlir::Operation *createRealizedSetVL(mlir::OpBuilder &builder,
                                     mlir::Location loc, mlir::Value nValue,
                                     std::int64_t sew, llvm::StringRef lmul,
                                     weft::rvv::PolicyAttr policy) {
  mlir::OperationState state(loc, "weft_rvv.setvl");
  state.addOperands(nValue);
  state.addTypes(weft::rvv::VLType::get(builder.getContext()));
  weft::rvv::populateRVVSelectedBodyConfigAttrs(builder, state, sew, lmul,
                                                policy);
  return builder.create(state);
}

weft::rvv::WithVLOp createRealizedWithVL(
    mlir::OpBuilder &builder, mlir::Location loc, mlir::Value vlValue,
    std::int64_t sew,
    llvm::StringRef lmul, weft::rvv::PolicyAttr policy) {
  mlir::OperationState state(loc, "weft_rvv.with_vl");
  state.addOperands(vlValue);
  weft::rvv::populateRVVSelectedBodyConfigAttrs(builder, state, sew, lmul,
                                                policy);
  state.addRegion();
  auto withVL = llvm::cast<weft::rvv::WithVLOp>(builder.create(state));
  withVL.getBody().emplaceBlock();
  return withVL;
}

mlir::Type getGenericVectorType(mlir::OpBuilder &builder, std::int64_t sew,
                                llvm::StringRef lmul) {
  mlir::Type elementType = builder.getIntegerType(sew);
  return weft::rvv::VectorType::get(builder.getContext(), elementType, lmul);
}

mlir::Type getStage1GenericMaskType(mlir::OpBuilder &builder) {
  return weft::rvv::MaskType::get(builder.getContext(), builder.getI32Type(),
                                  weft::rvv::getRVVLMULM1());
}

mlir::Type getGenericMaskTypeForVector(mlir::OpBuilder &builder,
                                       mlir::Value vector) {
  auto vectorType = llvm::dyn_cast<weft::rvv::VectorType>(vector.getType());
  if (!vectorType)
    return getStage1GenericMaskType(builder);
  return weft::rvv::MaskType::get(builder.getContext(),
                                  vectorType.getElementType(),
                                  vectorType.getLmul());
}

mlir::Type getGenericIndexVectorType(mlir::OpBuilder &builder,
                                     std::int64_t indexEEW,
                                     llvm::StringRef lmul) {
  mlir::Type elementType = indexEEW == 32 ? builder.getI32Type()
                                          : builder.getIntegerType(indexEEW);
  return weft::rvv::IndexVectorType::get(builder.getContext(), elementType,
                                         lmul);
}

mlir::Operation *createRealizedGenericLoad(mlir::OpBuilder &builder,
                                           mlir::Location loc,
                                           mlir::Value buffer,
                                           mlir::Value vl, std::int64_t sew,
                                           llvm::StringRef lmul) {
  mlir::OperationState state(loc, "weft_rvv.load");
  state.addOperands({buffer, vl});
  state.addTypes(getGenericVectorType(builder, sew, lmul));
  return builder.create(state);
}

mlir::Operation *createRealizedGenericSplat(mlir::OpBuilder &builder,
                                            mlir::Location loc,
                                            mlir::Value scalar,
                                            mlir::Value vl, std::int64_t sew,
                                            llvm::StringRef lmul) {
  mlir::OperationState state(loc, "weft_rvv.splat");
  state.addOperands({scalar, vl});
  state.addTypes(getGenericVectorType(builder, sew, lmul));
  return builder.create(state);
}

mlir::Operation *createRealizedGenericCompare(mlir::OpBuilder &builder,
                                              mlir::Location loc,
                                              mlir::Value lhs,
                                              mlir::Value rhs,
                                              mlir::Value vl,
                                              llvm::StringRef kind) {
  mlir::OperationState state(loc, "weft_rvv.compare");
  state.addOperands({lhs, rhs, vl});
  state.addAttribute("kind", builder.getStringAttr(kind));
  state.addTypes(getGenericMaskTypeForVector(builder, lhs));
  return builder.create(state);
}

mlir::Operation *createRealizedGenericIndexLoad(mlir::OpBuilder &builder,
                                                mlir::Location loc,
                                                mlir::Value index,
                                                mlir::Value vl,
                                                std::int64_t indexEEW,
                                                llvm::StringRef lmul) {
  mlir::OperationState state(loc, "weft_rvv.index_load");
  state.addOperands({index, vl});
  state.addAttribute("index_eew", builder.getI64IntegerAttr(indexEEW));
  state.addTypes(getGenericIndexVectorType(builder, indexEEW, lmul));
  return builder.create(state);
}

llvm::Expected<mlir::Operation *> createRealizedGenericMaskedLoad(
    mlir::OpBuilder &builder, mlir::Location loc, mlir::Value source,
    mlir::Value mask, mlir::Value passthrough, mlir::Value vl) {
  mlir::OperationState state(loc, "weft_rvv.masked_load");
  state.addOperands({source, mask, passthrough, vl});
  state.addAttribute("memory_form",
                     builder.getStringAttr("masked-unit-load"));
  state.addAttribute(
      "inactive_lane_policy",
      builder.getStringAttr("preserve-passthrough-on-false-lanes"));
  state.addTypes(passthrough.getType());
  return builder.create(state);
}

llvm::Expected<mlir::Operation *> createRealizedGenericMaskedStridedLoad(
    mlir::OpBuilder &builder, mlir::Location loc, mlir::Value source,
    mlir::Value mask, mlir::Value passthrough, mlir::Value stride,
    mlir::Value vl) {
  mlir::OperationState state(loc, "weft_rvv.masked_strided_load");
  state.addOperands({source, mask, passthrough, stride, vl});
  state.addAttribute("memory_form",
                     builder.getStringAttr("masked-strided-load"));
  state.addAttribute("stride_unit", builder.getStringAttr("byte"));
  state.addAttribute(
      "inactive_lane_policy",
      builder.getStringAttr("preserve-passthrough-on-false-lanes"));
  state.addTypes(passthrough.getType());
  return builder.create(state);
}

llvm::Expected<mlir::Operation *> createRealizedGenericMaskedIndexedLoad(
    mlir::OpBuilder &builder, mlir::Location loc, mlir::Value source,
    mlir::Value indices, mlir::Value mask, mlir::Value passthrough,
    mlir::Value vl, std::int64_t indexEEW, llvm::StringRef offsetUnit) {
  mlir::OperationState state(loc, "weft_rvv.masked_indexed_load");
  state.addOperands({source, indices, mask, passthrough, vl});
  state.addAttribute("index_eew", builder.getI64IntegerAttr(indexEEW));
  state.addAttribute("offset_unit", builder.getStringAttr(offsetUnit));
  state.addAttribute("memory_form",
                     builder.getStringAttr("masked-indexed-load"));
  state.addAttribute(
      "inactive_lane_policy",
      builder.getStringAttr("preserve-passthrough-on-false-lanes"));
  state.addTypes(passthrough.getType());
  return builder.create(state);
}

void createRealizedGenericStore(mlir::OpBuilder &builder, mlir::Location loc,
                                mlir::Value out, mlir::Value value,
                                mlir::Value vl) {
  mlir::OperationState state(loc, "weft_rvv.store");
  state.addOperands({out, value, vl});
  (void)builder.create(state);
}

void createRealizedGenericMaskedStridedStore(mlir::OpBuilder &builder,
                                             mlir::Location loc,
                                             mlir::Value out,
                                             mlir::Value mask,
                                             mlir::Value value,
                                             mlir::Value stride,
                                             mlir::Value vl) {
  mlir::OperationState state(loc, "weft_rvv.masked_strided_store");
  state.addOperands({out, mask, value, stride, vl});
  state.addAttribute("memory_form",
                     builder.getStringAttr("masked-strided-store"));
  state.addAttribute("stride_unit", builder.getStringAttr("byte"));
  state.addAttribute(
      "inactive_lane_policy",
      builder.getStringAttr("preserve-output-on-false-lanes"));
  (void)builder.create(state);
}

void createRealizedGenericMaskedIndexedStore(
    mlir::OpBuilder &builder, mlir::Location loc, mlir::Value destination,
    mlir::Value indices, mlir::Value mask, mlir::Value value, mlir::Value vl,
    std::int64_t indexEEW, llvm::StringRef offsetUnit,
    llvm::StringRef indexUniqueness) {
  mlir::OperationState state(loc, "weft_rvv.masked_indexed_store");
  state.addOperands({destination, indices, mask, value, vl});
  state.addAttribute("index_eew", builder.getI64IntegerAttr(indexEEW));
  state.addAttribute("offset_unit", builder.getStringAttr(offsetUnit));
  state.addAttribute("index_uniqueness",
                     builder.getStringAttr(indexUniqueness));
  state.addAttribute("memory_form",
                     builder.getStringAttr("masked-indexed-store"));
  state.addAttribute(
      "inactive_lane_policy",
      builder.getStringAttr("preserve-output-on-false-lanes"));
  (void)builder.create(state);
}

template <typename BodyOpT>
weft::rvv::WithVLOp createComputedMaskMemoryWithVL(
    const VariantLoweringBoundaryRequest &request, BodyOpT body,
    std::int64_t sew, llvm::StringRef lmul) {
  mlir::OpBuilder &builder = request.getBuilder();
  mlir::Location loc = body->getLoc();

  builder.setInsertionPoint(body.getOperation());
  auto setvl = llvm::cast<weft::rvv::SetVLOp>(
      createRealizedSetVL(builder, loc, body.getN(), sew, lmul,
                          body.getPolicy()));
  return createRealizedWithVL(builder, loc, setvl.getVl(), sew, lmul,
                              body.getPolicy());
}

template <typename BodyOpT>
std::pair<weft::rvv::LoadOp, weft::rvv::LoadOp>
createComputedMaskMemoryCompareLoads(
    mlir::OpBuilder &builder, mlir::Location loc, BodyOpT body, mlir::Value vl,
    std::int64_t sew, llvm::StringRef lmul) {
  auto compareLhsLoad =
      llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
          builder, loc, body.getCompareLhs(), vl, sew, lmul));
  auto compareRhsLoad =
      llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
          builder, loc, body.getCompareRhs(), vl, sew, lmul));
  return {compareLhsLoad, compareRhsLoad};
}

template <typename BodyOpT>
weft::rvv::CompareOp createComputedMaskMemoryCompareFromLoads(
    mlir::OpBuilder &builder, mlir::Location loc, BodyOpT body,
    weft::rvv::LoadOp compareLhsLoad, weft::rvv::LoadOp compareRhsLoad,
    mlir::Value vl) {
  return llvm::cast<weft::rvv::CompareOp>(
      createRealizedGenericCompare(builder, loc, compareLhsLoad.getLoaded(),
                                   compareRhsLoad.getLoaded(), vl,
                                   body.getPredicateKind()));
}

template <typename BodyOpT>
llvm::Expected<weft::rvv::WithVLOp> realizeComputedMaskMemoryLoadStore(
    const VariantLoweringBoundaryRequest &request, BodyOpT body) {
  std::int64_t sew = static_cast<std::int64_t>(body.getSew());
  llvm::StringRef lmul = body.getLmul();
  weft::rvv::WithVLOp withVL =
      createComputedMaskMemoryWithVL(request, body, sew, lmul);
  mlir::OpBuilder &builder = request.getBuilder();
  mlir::Location loc = body->getLoc();
  mlir::Value vl = withVL.getVl();

  builder.setInsertionPointToStart(&withVL.getBody().front());
  auto compareLoads =
      createComputedMaskMemoryCompareLoads(builder, loc, body, vl, sew, lmul);
  auto oldDestinationLoad =
      llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
          builder, loc, body.getDestination(), vl, sew, lmul));
  auto compare = createComputedMaskMemoryCompareFromLoads(
      builder, loc, body, compareLoads.first, compareLoads.second, vl);
  llvm::Expected<mlir::Operation *> maskedLoad =
      createRealizedGenericMaskedLoad(builder, loc, body.getSource(),
                                      compare.getMask(),
                                      oldDestinationLoad.getLoaded(), vl);
  if (!maskedLoad)
    return maskedLoad.takeError();
  createRealizedGenericStore(builder, loc, body.getDestination(),
                             (*maskedLoad)->getResult(0), vl);
  body->erase();
  return withVL;
}

} // namespace

bool isPreRealizedRVVComputedMaskMemoryClusterOp(mlir::Operation *op) {
  return llvm::isa<weft::rvv::TypedComputedMaskMemoryPreRealizedBodyOp,
                   weft::rvv::TypedComputedMaskStridedStorePreRealizedBodyOp,
                   weft::rvv::TypedComputedMaskStridedLoadPreRealizedBodyOp,
                   weft::rvv::TypedComputedMaskIndexedGatherPreRealizedBodyOp,
                   weft::rvv::
                       TypedRuntimeScalarComputedMaskIndexedGatherPreRealizedBodyOp,
                   weft::rvv::TypedComputedMaskIndexedScatterPreRealizedBodyOp,
                   weft::rvv::
                       TypedRuntimeScalarComputedMaskIndexedScatterPreRealizedBodyOp>(
      op);
}

llvm::Expected<weft::rvv::WithVLOp>
realizePreRealizedRVVComputedMaskMemoryOwner(
    const VariantLoweringBoundaryRequest &request, mlir::Operation *bodyOp) {
  if (!bodyOp)
    return makeRVVPluginError(
        "computed-mask memory selected-body realization owner requires a "
        "pre-realized RVV body op");
  if (!isPreRealizedRVVComputedMaskMemoryClusterOp(bodyOp))
    return makeRVVPluginError(
        "computed-mask memory selected-body realization owner received a "
        "body outside its RVV-owned realization family");

  weft::exec::VariantOp variant = request.getVariant();
  weft::exec::KernelOp kernel = request.getKernel();
  if (!variant || !kernel)
    return makeRVVPluginError(
        "pre-realized RVV computed-mask memory selected-body realization "
        "requires materialized kernel and variant");

  mlir::OpBuilder &builder = request.getBuilder();
  mlir::OpBuilder::InsertionGuard guard(builder);

  if (auto body =
          llvm::dyn_cast<weft::rvv::TypedComputedMaskMemoryPreRealizedBodyOp>(
              bodyOp)) {
    return realizeComputedMaskMemoryLoadStore(request, body);
  }

  if (auto body = llvm::dyn_cast<
          weft::rvv::TypedComputedMaskStridedStorePreRealizedBodyOp>(bodyOp)) {
    std::int64_t sew = static_cast<std::int64_t>(body.getSew());
    llvm::StringRef lmul = body.getLmul();
    weft::rvv::WithVLOp withVL =
        createComputedMaskMemoryWithVL(request, body, sew, lmul);
    mlir::Location loc = body->getLoc();
    mlir::Value vl = withVL.getVl();

    builder.setInsertionPointToStart(&withVL.getBody().front());
    auto compareLoads = createComputedMaskMemoryCompareLoads(builder, loc, body,
                                                            vl, sew, lmul);
    auto sourceLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getSource(), vl, sew, lmul));
    auto compare = createComputedMaskMemoryCompareFromLoads(
        builder, loc, body, compareLoads.first, compareLoads.second, vl);
    createRealizedGenericMaskedStridedStore(
        builder, loc, body.getDestination(), compare.getMask(),
        sourceLoad.getLoaded(), body.getDestinationStride(), vl);
    body->erase();
    return withVL;
  }

  if (auto body = llvm::dyn_cast<
          weft::rvv::TypedComputedMaskStridedLoadPreRealizedBodyOp>(bodyOp)) {
    std::int64_t sew = static_cast<std::int64_t>(body.getSew());
    llvm::StringRef lmul = body.getLmul();
    weft::rvv::WithVLOp withVL =
        createComputedMaskMemoryWithVL(request, body, sew, lmul);
    mlir::Location loc = body->getLoc();
    mlir::Value vl = withVL.getVl();

    builder.setInsertionPointToStart(&withVL.getBody().front());
    auto compareLoads = createComputedMaskMemoryCompareLoads(builder, loc, body,
                                                            vl, sew, lmul);
    auto oldDestinationLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getDestination(), vl, sew, lmul));
    auto compare = createComputedMaskMemoryCompareFromLoads(
        builder, loc, body, compareLoads.first, compareLoads.second, vl);
    llvm::Expected<mlir::Operation *> maskedStridedLoad =
        createRealizedGenericMaskedStridedLoad(
            builder, loc, body.getSource(), compare.getMask(),
            oldDestinationLoad.getLoaded(), body.getSourceStride(), vl);
    if (!maskedStridedLoad)
      return maskedStridedLoad.takeError();
    createRealizedGenericStore(builder, loc, body.getDestination(),
                               (*maskedStridedLoad)->getResult(0), vl);
    body->erase();
    return withVL;
  }

  if (auto body = llvm::dyn_cast<
          weft::rvv::TypedComputedMaskIndexedGatherPreRealizedBodyOp>(bodyOp)) {
    std::int64_t sew = static_cast<std::int64_t>(body.getSew());
    llvm::StringRef lmul = body.getLmul();
    std::int64_t indexEEW = static_cast<std::int64_t>(body.getIndexEew());
    weft::rvv::WithVLOp withVL =
        createComputedMaskMemoryWithVL(request, body, sew, lmul);
    mlir::Location loc = body->getLoc();
    mlir::Value vl = withVL.getVl();

    builder.setInsertionPointToStart(&withVL.getBody().front());
    auto compareLoads = createComputedMaskMemoryCompareLoads(builder, loc, body,
                                                            vl, sew, lmul);
    auto oldDestinationLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getDestination(), vl, sew, lmul));
    auto indexLoad =
        llvm::cast<weft::rvv::IndexLoadOp>(createRealizedGenericIndexLoad(
            builder, loc, body.getIndex(), vl, indexEEW, lmul));
    auto compare = createComputedMaskMemoryCompareFromLoads(
        builder, loc, body, compareLoads.first, compareLoads.second, vl);
    llvm::Expected<mlir::Operation *> maskedIndexedLoad =
        createRealizedGenericMaskedIndexedLoad(
            builder, loc, body.getSource(), indexLoad.getLoaded(),
            compare.getMask(), oldDestinationLoad.getLoaded(), vl, indexEEW,
            body.getOffsetUnit());
    if (!maskedIndexedLoad)
      return maskedIndexedLoad.takeError();
    createRealizedGenericStore(builder, loc, body.getDestination(),
                               (*maskedIndexedLoad)->getResult(0), vl);
    body->erase();
    return withVL;
  }

  if (auto body = llvm::dyn_cast<
          weft::rvv::
              TypedRuntimeScalarComputedMaskIndexedGatherPreRealizedBodyOp>(
          bodyOp)) {
    std::int64_t sew = static_cast<std::int64_t>(body.getSew());
    llvm::StringRef lmul = body.getLmul();
    std::int64_t indexEEW = static_cast<std::int64_t>(body.getIndexEew());
    weft::rvv::WithVLOp withVL =
        createComputedMaskMemoryWithVL(request, body, sew, lmul);
    mlir::Location loc = body->getLoc();
    mlir::Value vl = withVL.getVl();

    builder.setInsertionPointToStart(&withVL.getBody().front());
    auto lhsLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getLhs(), vl, sew, lmul));
    auto rhsScalarSplat =
        llvm::cast<weft::rvv::SplatOp>(createRealizedGenericSplat(
            builder, loc, body.getRhsScalar(), vl, sew, lmul));
    auto oldDestinationLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getDestination(), vl, sew, lmul));
    auto indexLoad =
        llvm::cast<weft::rvv::IndexLoadOp>(createRealizedGenericIndexLoad(
            builder, loc, body.getIndex(), vl, indexEEW, lmul));
    auto compare = llvm::cast<weft::rvv::CompareOp>(
        createRealizedGenericCompare(builder, loc, lhsLoad.getLoaded(),
                                     rhsScalarSplat.getBroadcast(), vl,
                                     body.getPredicateKind()));
    llvm::Expected<mlir::Operation *> maskedIndexedLoad =
        createRealizedGenericMaskedIndexedLoad(
            builder, loc, body.getSource(), indexLoad.getLoaded(),
            compare.getMask(), oldDestinationLoad.getLoaded(), vl, indexEEW,
            body.getOffsetUnit());
    if (!maskedIndexedLoad)
      return maskedIndexedLoad.takeError();
    createRealizedGenericStore(builder, loc, body.getDestination(),
                               (*maskedIndexedLoad)->getResult(0), vl);
    body->erase();
    return withVL;
  }

  if (auto body =
          llvm::dyn_cast<weft::rvv::
                             TypedComputedMaskIndexedScatterPreRealizedBodyOp>(
              bodyOp)) {
    std::int64_t sew = static_cast<std::int64_t>(body.getSew());
    llvm::StringRef lmul = body.getLmul();
    std::int64_t indexEEW = static_cast<std::int64_t>(body.getIndexEew());
    weft::rvv::WithVLOp withVL =
        createComputedMaskMemoryWithVL(request, body, sew, lmul);
    mlir::Location loc = body->getLoc();
    mlir::Value vl = withVL.getVl();

    builder.setInsertionPointToStart(&withVL.getBody().front());
    auto compareLoads = createComputedMaskMemoryCompareLoads(builder, loc, body,
                                                            vl, sew, lmul);
    auto sourceLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getSource(), vl, sew, lmul));
    auto indexLoad =
        llvm::cast<weft::rvv::IndexLoadOp>(createRealizedGenericIndexLoad(
            builder, loc, body.getIndex(), vl, indexEEW, lmul));
    auto compare = createComputedMaskMemoryCompareFromLoads(
        builder, loc, body, compareLoads.first, compareLoads.second, vl);
    createRealizedGenericMaskedIndexedStore(
        builder, loc, body.getDestination(), indexLoad.getLoaded(),
        compare.getMask(), sourceLoad.getLoaded(), vl, indexEEW,
        body.getOffsetUnit(), body.getIndexUniqueness());
    body->erase();
    return withVL;
  }

  if (auto body = llvm::dyn_cast<
          weft::rvv::
              TypedRuntimeScalarComputedMaskIndexedScatterPreRealizedBodyOp>(
          bodyOp)) {
    std::int64_t sew = static_cast<std::int64_t>(body.getSew());
    llvm::StringRef lmul = body.getLmul();
    std::int64_t indexEEW = static_cast<std::int64_t>(body.getIndexEew());
    weft::rvv::WithVLOp withVL =
        createComputedMaskMemoryWithVL(request, body, sew, lmul);
    mlir::Location loc = body->getLoc();
    mlir::Value vl = withVL.getVl();

    builder.setInsertionPointToStart(&withVL.getBody().front());
    auto lhsLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getLhs(), vl, sew, lmul));
    auto rhsScalarSplat =
        llvm::cast<weft::rvv::SplatOp>(createRealizedGenericSplat(
            builder, loc, body.getRhsScalar(), vl, sew, lmul));
    auto sourceLoad =
        llvm::cast<weft::rvv::LoadOp>(createRealizedGenericLoad(
            builder, loc, body.getSource(), vl, sew, lmul));
    auto indexLoad =
        llvm::cast<weft::rvv::IndexLoadOp>(createRealizedGenericIndexLoad(
            builder, loc, body.getIndex(), vl, indexEEW, lmul));
    auto compare = llvm::cast<weft::rvv::CompareOp>(
        createRealizedGenericCompare(builder, loc, lhsLoad.getLoaded(),
                                     rhsScalarSplat.getBroadcast(), vl,
                                     body.getPredicateKind()));
    createRealizedGenericMaskedIndexedStore(
        builder, loc, body.getDestination(), indexLoad.getLoaded(),
        compare.getMask(), sourceLoad.getLoaded(), vl, indexEEW,
        body.getOffsetUnit(), body.getIndexUniqueness());
    body->erase();
    return withVL;
  }

  return makeRVVPluginError(
      "computed-mask memory selected-body realization owner found an "
      "unsupported pre-realized body op");
}

} // namespace weft::plugin::rvv
