//===-- KTIRMapAndTile.cpp --------------------------------------*- c++ -*-===//
//
// Part of the Dataflow Scheduler project.
//
// Licensed under the Apache License, Version 2.0 (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
//     http://www.apache.org/licenses/LICENSE-2.0
//
// Unless required by applicable law or agreed to in writing, software
// distributed under the License is distributed on an "AS IS" BASIS,
// WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
// See the License for the specific language governing permissions and
// limitations under the License.
//
//===----------------------------------------------------------------------===//

#include <llvm/ADT/STLExtras.h>
#include <llvm/ADT/SmallVector.h>
#include <llvm/Support/DebugLog.h>
#include <llvm/Support/MathExtras.h>
#include <mlir/Dialect/Func/IR/FuncOps.h>
#include <mlir/Dialect/Linalg/IR/Linalg.h>
#include <mlir/Dialect/Linalg/Transforms/Transforms.h>
#include <mlir/Dialect/SCF/IR/SCF.h>
#include <mlir/Dialect/Tensor/IR/Tensor.h>
#include <mlir/Dialect/Tensor/Transforms/Transforms.h>
#include <mlir/Dialect/Utils/StaticValueUtils.h>
#include <mlir/IR/Builders.h>
#include <mlir/IR/BuiltinAttributes.h>
#include <mlir/IR/BuiltinTypeInterfaces.h>
#include <mlir/IR/Operation.h>
#include <mlir/IR/PatternMatch.h>
#include <mlir/IR/Value.h>
#include <mlir/IR/Verifier.h>
#include <mlir/Interfaces/DestinationStyleOpInterface.h>
#include <mlir/Interfaces/InferTypeOpInterface.h>
#include <mlir/Pass/Pass.h>
#include <mlir/Transforms/GreedyPatternRewriteDriver.h>
#include <mlir/Transforms/RegionUtils.h>

#include <algorithm>
#include <cstdint>

#include "Utils.h"
#include "dataflow-scheduler/Conversion/backend/ScheduleIRToDFIR/KTDFLowToDFIR/DataTransferLowering.h"
#include "dataflow-scheduler/Conversion/frontend/KTIRToScheduleIR/Passes.h"  // IWYU pragma: keep
#include "dataflow-scheduler/Dialect/KTDF/KTDF.h"
#include "dataflow-scheduler/Dialect/KTDFArch/Analysis/DeviceManager.h"
#include "dataflow-scheduler/Dialect/KTDFArch/Analysis/Mapping.h"
#include "dataflow-scheduler/Dialect/KTDFArch/KTDFArch.h"
#include "dataflow-scheduler/Dialect/KTDFArch/KTDFArchAttributes.h"
#include "dataflow-scheduler/Dialect/KTDFArch/KTDFArchIntrinsics.h"
#include "dataflow-scheduler/Dialect/KTDPLowering/KTDPLowering.h"

#define PASS_NAME "ktir-map-and-tile"
#define DEBUG_TYPE PASS_NAME

static llvm::cl::opt<bool> disable_this_pass(
    "disable-" PASS_NAME, llvm::cl::desc("Disable KTIR Map and Tile pass"),
    llvm::cl::init(false));

using namespace scheduler;

namespace scheduler {
#define GEN_PASS_DEF_KTIRMAPANDTILEPASS
#include "dataflow-scheduler/Conversion/frontend/KTIRToScheduleIR/Passes.h.inc"
}  // namespace scheduler

namespace {

const auto kSkipRegions = mlir::OpPrintingFlags().skipRegions();

using I64Vec = llvm::SmallVector<int64_t>;

struct KTIRMapAndTilePass
    : public impl::KTIRMapAndTilePassBase<KTIRMapAndTilePass> {
  using KTIRMapAndTilePassBase<KTIRMapAndTilePass>::KTIRMapAndTilePassBase;

  void runOnOperation() override;
};

/// Given a shape and a target vector_length, compute per-dimension tile sizes
/// working rightmost-first until the product of covered dims reaches
/// vector_length.  Uncovered dims (leftmost) get tile size 1 so a loop is
/// generated for them; covered dims get the largest value that divides both
/// the dim size and the remaining vector-length product.
[[nodiscard]] auto determineTileSizes(
    llvm::ArrayRef<int64_t> shape, int64_t vector_length,
    llvm::SmallVectorImpl<int64_t>& tile_sizes) -> llvm::LogicalResult {
  const int64_t rank = shape.size();

  // Find how many rightmost dims are needed to cover vector_length.
  int64_t product = 1;
  unsigned covered_dims = 0;
  while (covered_dims < shape.size()) {
    const auto size = shape[shape.size() - covered_dims - 1];
    if (mlir::ShapedType::isDynamic(size)) {
      // There weren't enough statically known dims to cover the vector size.
      return llvm::failure();
    }

    product *= size;
    covered_dims++;
    if (product >= vector_length) {
      break;
    }
  }

  // Uncovered dims (leftmost) get tile size 1 — a loop is generated that
  // iterates over the full extent one element at a time.
  tile_sizes.resize(rank, 1);

  // Covered dims get a size that divides both the dim and the remaining
  // product.
  int64_t remaining = vector_length;
  for (int64_t i = rank - 1; i >= rank - covered_dims; --i) {
    const auto size = std::min(std::gcd(shape[i], remaining), shape[i]);
    tile_sizes[i] = size;
    remaining = std::max<int64_t>(remaining / size, 1);
  }

  return llvm::success();
}

auto determineTileSizes(mlir::linalg::LinalgOp op,
                        mlir::ktdf_arch::Mapping& mapping,
                        llvm::SmallVectorImpl<int64_t>& tile_sizes)
    -> llvm::LogicalResult {
  if (!op.hasPureTensorSemantics() || op->getNumResults() == 0) {
    return op->emitError("tiling error: expected pure tensor semantics");
  }
  const auto result_type =
      mlir::cast<mlir::RankedTensorType>(op->getResult(0).getType());
  if (!llvm::all_equal(op->getResultTypes())) {
    // Current implementation only allows for uniform tiling of all results.
    return op.emitError("tiling error: expected matching result types");
  }

  LDBG() << "determining tile sizes for "
         << mlir::OpWithFlags(op, kSkipRegions);

  // Map the op to a compute resource, if it isn't already.
  auto compute =
      mapping.getOrMap(op, mapping.byKind().getDefaultCompute().getKind());
  assert(compute && "no default compute resource");

  LDBG() << "  compute: " << mlir::OpWithFlags(compute, kSkipRegions);

  // Determine the desired vector width on the compute resource.
  const auto element_type = result_type.getElementType();
  const auto simd_feature =
      compute.getFeature<mlir::ktdf_arch::feature::SIMD>();
  const auto vector_length =
      std::max(simd_feature.getLanes(element_type), int64_t{1});

  // Annotate the vector width as the throttle for this operation.
  setThrottle(op, vector_length);

  // The tile-sizes vector must cover every loop dimension (getNumLoops()).
  // Reduction dimensions are skipped (tile size = 0) so the tiling infra does
  // not create a loop for them.  Only parallel dimensions are tiled, using the
  // same rightmost-first shape-based algorithm as before.
  // Collect the loop bounds for each dimension by querying the op directly.
  // getStaticLoopRanges() scans all operand indexing maps so it works
  // regardless of whether any single operand has a full-rank map (e.g. when
  // an input has a broadcast/projection indexing map that skips some dims).
  const auto loop_ranges = op.getStaticLoopRanges();
  I64Vec parallel_loop_indices;
  I64Vec parallel_shape;
  for (auto [index, type] : llvm::enumerate(op.getIteratorTypesArray())) {
    if (type == mlir::utils::IteratorType::parallel) {
      parallel_loop_indices.push_back(index);
      parallel_shape.push_back(loop_ranges[index]);
    }
  }

  LDBG_OS([&](llvm::raw_ostream& os) {
    os << "  parallel_shape: {";
    llvm::interleaveComma(parallel_shape, os);
    os << "}";
  });

  // Compute tile sizes for the parallel dimensions.
  I64Vec parallel_tile_sizes;
  if (failed(::determineTileSizes(parallel_shape, vector_length,
                                  parallel_tile_sizes))) {
    return op->emitError("tiling error: inner dimensions not tileable");
  }

  // Assemble the final vector: 0 for reduction dims, computed size for
  // parallel dims.
  tile_sizes.resize(loop_ranges.size(), 0);
  for (int64_t k = 0; k < static_cast<int64_t>(parallel_loop_indices.size());
       ++k) {
    tile_sizes[parallel_loop_indices[k]] = parallel_tile_sizes[k];
  }

  LDBG_OS([&](llvm::raw_ostream& os) {
    os << "  tile_sizes: {";
    llvm::interleaveComma(tile_sizes, os);
    os << "}";
  });

  return llvm::success();
}

auto reifySize(mlir::OpBuilder& builder, mlir::Location loc, mlir::Value value,
               int64_t dim) -> mlir::FailureOr<mlir::OpFoldResult> {
  if (auto result = llvm::dyn_cast<mlir::OpResult>(value); result) {
    if (auto iface =
            result.getDefiningOp<mlir::ReifyRankedShapedTypeOpInterface>();
        iface) {
      return iface.reifyDimOfResult(builder, result.getResultNumber(), dim);
    }
  }

  const auto type = llvm::dyn_cast<mlir::RankedTensorType>(value.getType());
  if (!type) {
    return llvm::failure();
  }

  if (const auto size = type.getShape()[dim];
      !mlir::ShapedType::isDynamic(size)) {
    return mlir::OpFoldResult(builder.getI64IntegerAttr(size));
  }

  return mlir::OpFoldResult(
      mlir::tensor::DimOp::create(builder, loc, value, dim));
}

auto compressInput(mlir::RewriterBase& rewriter, mlir::linalg::LinalgOp op,
                   mlir::OpOperand* input) -> llvm::LogicalResult {
  const auto type =
      llvm::dyn_cast<mlir::RankedTensorType>(input->get().getType());
  const auto bcast_dims = op.getMatchingIndexingMap(input).getBroadcastDims();
  if (!type || bcast_dims.empty()) {
    return llvm::failure();
  }

  const auto zero = rewriter.getI64IntegerAttr(0);
  const auto one = rewriter.getI64IntegerAttr(1);

  llvm::SmallVector<mlir::Range> ranges;
  ranges.reserve(type.getRank());
  for (auto dim : llvm::iota_range<int64_t>(0, type.getRank(), false)) {
    const auto size = reifySize(rewriter, op.getLoc(), input->get(), dim);
    if (failed(size)) {
      return llvm::failure();
    }
    ranges.push_back({zero, *size, one});
  }

  for (auto dim : bcast_dims) {
    ranges[dim] = {zero, one, zero};
  }

  input->set(mlir::tensor::ExtractSliceOp::create(rewriter, op.getLoc(),
                                                  input->get(), ranges));
  return llvm::success();
}

auto compressInputs(mlir::RewriterBase& rewriter, mlir::linalg::LinalgOp op)
    -> llvm::LogicalResult {
  rewriter.startOpModification(op);
  auto changed = false;

  for (auto* const input : op.getDpsInputOperands()) {
    changed |= succeeded(compressInput(rewriter, op, input));
  }

  if (!changed) {
    rewriter.cancelOpModification(op);
    return llvm::failure();
  }

  LDBG() << "compressed " << mlir::OpWithFlags(op, kSkipRegions);
  rewriter.finalizeOpModification(op);
  return llvm::success();
}

auto tile(mlir::RewriterBase& rewriter, mlir::linalg::LinalgOp& op,
          mlir::ktdf_arch::Mapping& mapping)
    -> llvm::FailureOr<mlir::scf::LoopVector> {
  rewriter.setInsertionPoint(op);

  // Remove needless dependencies on broadcasted dimensions.
  std::ignore = compressInputs(rewriter, op);

  // Determine tile sizes from output operand shape (needed for loop creation).
  I64Vec tile_sizes;
  if (failed(determineTileSizes(op, mapping, tile_sizes))) {
    return llvm::failure();
  }
  if (tile_sizes.empty()) {
    op.emitError("tiling error: no tileable dimensions");
    return llvm::failure();
  }

  // Tile the linalg.generic operation with the computed tile sizes
  mlir::linalg::LinalgTilingOptions tiling_options;
  tiling_options.setTileSizes(tile_sizes);
  tiling_options.setLoopType(mlir::linalg::LinalgTilingLoopType::Loops);
  const auto maybe_tiling = tileLinalgOp(rewriter, op, tiling_options);
  if (failed(maybe_tiling)) {
    op->emitError("tiling error: unable to create loops");
    return llvm::failure();
  }

  // Annotate the created loops with their iterator type.
  {
    unsigned loop_index = 0;
    const auto iterator_types = op.getIteratorTypesArray();
    for (auto [dim, tile_size] : llvm::enumerate(tile_sizes)) {
      if (tile_size != 0) {
        // FIXME: Put the attribute name somewhere else.
        maybe_tiling->loops[loop_index++]->setAttr(
            "loop_type",
            getLoopTypeAttr(rewriter.getContext(), iterator_types[dim]));
      }
    }
  }

  // Replace the old with the tiled op.
  maybe_tiling->op->setDiscardableAttrs(op->getRawDictionaryAttrs());
  rewriter.replaceOp(op, maybe_tiling->tensorResults);
  op = maybe_tiling->op;

  return llvm::map_to_vector(maybe_tiling->loops, [](mlir::Operation* op) {
    return llvm::cast<mlir::scf::ForOp>(op);
  });
}

auto lowerLoad(mlir::RewriterBase& rewriter, mlir::ktdp::LoadOp load,
               const AttrMapping& mem_space_map)
    -> llvm::FailureOr<mlir::ktdp_lowering::LoadOp> {
  llvm::SmallVector<mlir::Attribute> hops{getMemorySpace(load.getAccessTile())};
  auto* use = getSingleUse(load);
  if (use == nullptr) {
    if (load->use_empty()) {
      rewriter.eraseOp(load);
      return llvm::success(nullptr);
    }

    return load.emitError("tiling error: load has multiple uses");
  }

  // Erase all the via hops on the way to the `tensor.extract_slice`.
  while (auto via = llvm::dyn_cast<mlir::ktdf::ViaOp>(use->getOwner())) {
    llvm::append_range(hops, via.getHops());
    use = getSingleUse(via);
    if (use == nullptr) {
      if (via->use_empty()) {
        rewriter.eraseOp(via);
        rewriter.eraseOp(load);
        return llvm::success(nullptr);
      }

      return load.emitError("tiling error: load has multiple uses");
    }

    use->set(load);
    rewriter.eraseOp(via);
  }

  auto extract_slice =
      llvm::dyn_cast<mlir::tensor::ExtractSliceOp>(use->getOwner());
  if (!extract_slice) {
    auto diag = load->emitError("tiling error: no `tensor.extract_slice` sink");
    diag.attachNote(use->getOwner()->getLoc()) << "found this instead";
    return diag;
  }

  // Canonicalize the via hops, counting the load as a hop as well.
  for (auto& hop : hops) {
    hop = mem_space_map.map(hop);
  }
  hops.erase(std::unique(hops.begin(), hops.end()), hops.end());

  // Create the `ktdp_lowering.load` that captures the applied tiling.
  rewriter.setInsertionPointAfter(extract_slice);
  auto new_load = mlir::ktdp_lowering::LoadOp::create(
      rewriter, load.getLoc(), extract_slice.getType(), load.getAccessTile(),
      extract_slice);
  setThrottle(new_load, getThrottle(extract_slice->getOpResult(0)));

  // Add the hops back in after the load and replace `tensor.extract_slice`.
  mlir::Value loaded = new_load.getResult();
  if (auto via = llvm::ArrayRef(hops).drop_front(1); !via.empty()) {
    loaded = mlir::ktdf::ViaOp::create(rewriter, load.getLoc(), loaded,
                                       rewriter.getArrayAttr(via));
  }
  rewriter.replaceOp(extract_slice, loaded);
  rewriter.eraseOp(load);
  return new_load;
}

auto lowerStore(mlir::RewriterBase& rewriter, mlir::ktdp::StoreOp store,
                const AttrMapping& mem_space_map)
    -> llvm::FailureOr<mlir::ktdp_lowering::StoreOp> {
  llvm::SmallVector<mlir::Attribute> reverse_hops{
      getMemorySpace(store.getAccessTile())};
  auto source = llvm::dyn_cast<mlir::OpResult>(store.getDataTile());
  if (!source) {
    return store->emitError("tiling error: no data tile source");
  }

  llvm::SmallVector<mlir::Operation*> ops_to_erase;

  // Erase all the via hops on the way to the insert_slice.
  auto insert_slice =
      llvm::dyn_cast<mlir::tensor::InsertSliceOp>(source.getOwner());
  while (!insert_slice) {
    if (auto via = llvm::dyn_cast<mlir::ktdf::ViaOp>(source.getOwner()); via) {
      llvm::append_range(reverse_hops, via.getHops());
      source = llvm::dyn_cast<mlir::OpResult>(via.getOperand());
      if (!source) {
        return via->emitError("tiling error: no data tile source");
      }
      if (via->hasOneUse()) {
        rewriter.replaceOp(via, source);
      }
    } else if (auto loop = llvm::dyn_cast<mlir::scf::ForOp>(source.getOwner());
               loop) {
      source = llvm::dyn_cast<mlir::OpResult>(
          loop.getBody()->getTerminator()->getOperand(
              source.getResultNumber()));
      if (!source) {
        return loop.getBody()->getTerminator()->emitError(
            "tiling error: no data tile source");
      }
    } else if (auto expand = llvm::dyn_cast<mlir::tensor::ExpandShapeOp>(
                   source.getOwner());
               expand) {
      ops_to_erase.push_back(expand);
      source = llvm::dyn_cast<mlir::OpResult>(expand.getSrc());
      if (!source) {
        return expand->emitError("tiling error: no data tile source");
      }
    } else {
      return store->emitError("tiling error: no data tile source");
    }

    insert_slice =
        llvm::dyn_cast<mlir::tensor::InsertSliceOp>(source.getOwner());
  }

  // The new store is placed inside the tiled loop nest, but the access tile
  // may be defined after that loop nest. Hoist its definition above the nest.
  mlir::Value access_tile = store.getAccessTile();
  if (auto* def = access_tile.getDefiningOp(); def) {
    auto* nest = def->getBlock()->findAncestorOpInBlock(*insert_slice);
    if (nest &&
        failed(mlir::moveValueDefinitions(rewriter, access_tile, nest))) {
      return store->emitError(
          "tiling error: cannot hoist access tile above the tiled loop nest");
    }
  }

  // Canonicalize the via hops, counting the store as a hop as well.
  for (auto& hop : reverse_hops) {
    hop = mem_space_map.map(hop);
  }
  reverse_hops.erase(std::unique(reverse_hops.begin(), reverse_hops.end()),
                     reverse_hops.end());
  // Add the hops back in before the store.
  rewriter.setInsertionPoint(insert_slice);
  mlir::Value stored = insert_slice.getSource();
  if (auto reverse_via = llvm::MutableArrayRef(reverse_hops).drop_front(1);
      !reverse_via.empty()) {
    std::reverse(reverse_via.begin(), reverse_via.end());
    stored = mlir::ktdf::ViaOp::create(rewriter, store.getLoc(), stored,
                                       rewriter.getArrayAttr(reverse_via));
  }

  // Create the `ktdp_lowering.store` that captures the applied tiling.
  auto new_store = mlir::ktdp_lowering::StoreOp::create(
      rewriter, store.getLoc(), stored, store.getAccessTile(), insert_slice);
  setThrottle(new_store, getThrottle(insert_slice.getSourceMutable()));

  rewriter.eraseOp(store);
  for (auto* op : ops_to_erase) {
    rewriter.eraseOp(op);
  }
  rewriter.replaceAllUsesWith(insert_slice, insert_slice.getDest());
  rewriter.eraseOp(insert_slice);
  return new_store;
}

auto lowerLoadAndStore(mlir::RewriterBase& rewriter,
                       llvm::ArrayRef<mlir::ktdp::LoadOp> loads,
                       llvm::ArrayRef<mlir::ktdp::StoreOp> stores,
                       const AttrMapping& mem_space_map)
    -> llvm::LogicalResult {
  for (auto load : loads) {
    if (failed(lowerLoad(rewriter, load, mem_space_map))) {
      return llvm::failure();
    }
  }

  for (auto store : stores) {
    if (failed(lowerStore(rewriter, store, mem_space_map))) {
      return llvm::failure();
    }
  }

  return llvm::success();
}

void breakLoopCarriedDependencies(mlir::RewriterBase& rewriter,
                                  mlir::DestinationStyleOpInterface op) {
  rewriter.setInsertionPoint(op);
  for (auto& outs : op.getDpsInitsMutable()) {
    auto slice = outs.get().getDefiningOp<mlir::tensor::ExtractSliceOp>();
    if (!slice || !llvm::isa<mlir::BlockArgument>(slice.getSource())) {
      continue;
    }

    // FIMXE: This only works because we aren't tiling reduction dimensions!

    rewriter.replaceOp(slice, mlir::tensor::EmptyOp::create(
                                  rewriter, op.getLoc(), slice.getMixedSizes(),
                                  slice.getType().getElementType()));
  }
}

void dropIterArgs(mlir::RewriterBase& rewriter,
                  mlir::scf::LoopVector& loop_nest) {
  assert(!loop_nest.empty());

  // Create the new loop nest after the old one.
  mlir::OpBuilder::InsertionGuard guard(rewriter);
  rewriter.setInsertionPointAfter(loop_nest.front());
  const auto get_lb = [&](mlir::scf::ForOp loop) {
    return loop.getLowerBound();
  };
  const auto get_ub = [&](mlir::scf::ForOp loop) {
    return loop.getUpperBound();
  };
  const auto get_step = [&](mlir::scf::ForOp loop) { return loop.getStep(); };
  auto new_loops =
      mlir::scf::buildLoopNest(rewriter, loop_nest.front().getLoc(),
                               llvm::map_to_vector(loop_nest, get_lb),
                               llvm::map_to_vector(loop_nest, get_ub),
                               llvm::map_to_vector(loop_nest, get_step))
          .loops;

  // Move the loop body.
  auto& body = *loop_nest.back().getBody();
  auto& new_body = *new_loops.back().getBody();
  new_body.getOperations().splice(new_body.begin(), body.getOperations(),
                                  body.begin(),
                                  body.without_terminator().end());

  // Copy the attributes not set by buildLoopNest, update the result, and erase
  // the old loop, from inside to outside.
  for (auto [result, now] :
       llvm::zip_equal(llvm::reverse(loop_nest), llvm::reverse(new_loops))) {
    now->setDiscardableAttrs(result->getRawDictionaryAttrs());
    now.setUnsignedCmp(result.getUnsignedCmp());

    result.getInductionVar().replaceAllUsesWith(now.getInductionVar());
    if (!result.getBodyRegion().empty()) {
      rewriter.eraseBlock(result.getBody());
    }
    result->dropAllUses();
    rewriter.eraseOp(result);

    result = now;
  }
}

void bubbleOpExtractSlice(mlir::RewriterBase& rewriter,
                          mlir::tensor::ExtractSliceOp op,
                          const AttrMapping& mem_space_map) {
  while (auto via = op.getSource().getDefiningOp<mlir::ktdf::ViaOp>()) {
    rewriter.modifyOpInPlace(op, [&]() { op.setOperand(0, via.getOperand()); });
    rewriter.modifyOpInPlace(via, [&]() {
      via.getResult().setType(op.getType());
      via.setOperand(op);
    });
    rewriter.replaceAllUsesExcept(op, via, via);
    rewriter.moveOpBefore(op, via);
  }

  if (auto load = op.getSource().getDefiningOp<mlir::ktdp_lowering::LoadOp>();
      load) {
    rewriter.modifyOpInPlace(op, [&]() {
      std::ignore = mlir::ktdf_arch::Mappable::setMapsTo(
          op, mlir::ktdf_arch::MapsToAttr::get(
                  rewriter.getContext(),
                  {llvm::cast<mlir::ktdf_arch::ResourceSpecAttr>(
                      mem_space_map.map(getMemorySpace(load.getSource())))}));
    });
  }
}

auto broadcastInput(mlir::RewriterBase& rewriter, mlir::linalg::LinalgOp op,
                    mlir::OpOperand* input, const AttrMapping& mem_space_map)
    -> llvm::LogicalResult {
  const auto type =
      llvm::dyn_cast<mlir::RankedTensorType>(input->get().getType());
  const auto bcast_dims = op.getMatchingIndexingMap(input).getBroadcastDims();
  if (!type || bcast_dims.empty()) {
    return llvm::failure();
  }

  const auto vector_lanes =
      op->getAttrOfType<mlir::ktdf_arch::I64Attr>(kThrottleAttrName).getValue();
  const auto zero = rewriter.getI64IntegerAttr(0);
  const auto one = rewriter.getI64IntegerAttr(1);

  llvm::SmallVector<mlir::Range> ranges;
  ranges.reserve(type.getRank());
  int64_t elements = 1;
  for (auto dim : llvm::iota_range<int64_t>(0, type.getRank(), false)) {
    const auto size = reifySize(rewriter, op.getLoc(), input->get(), dim);
    if (failed(size)) {
      return llvm::failure();
    }
    ranges.push_back({zero, *size, one});

    if (llvm::is_contained(bcast_dims, dim)) {
      continue;
    }
    const auto static_size = mlir::getConstantIntValue(*size);
    if (!static_size ||
        llvm::MulOverflow(elements, *static_size, elements) != 0) {
      return llvm::failure();
    }
  }

  // The operand fills one vector, so only the lanes the other dimensions leave
  // are spread along the innermost broadcast dimension. A broadcast outside the
  // lanes keeps size 1.
  if (elements <= 0 || vector_lanes % elements != 0) {
    return llvm::failure();
  }
  const auto fill = vector_lanes / elements;
  if (fill == 1) {
    return llvm::failure();
  }

  for (auto dim : bcast_dims) {
    ranges[dim] = {zero, one, zero};
  }
  ranges[bcast_dims.back()] = {zero, rewriter.getI64IntegerAttr(fill), zero};

  auto broadcast = mlir::tensor::ExtractSliceOp::create(rewriter, op.getLoc(),
                                                        input->get(), ranges);
  input->set(broadcast);
  bubbleOpExtractSlice(rewriter, broadcast, mem_space_map);
  return llvm::success();
}

auto broadcastInputs(mlir::RewriterBase& rewriter, mlir::linalg::LinalgOp op,
                     const AttrMapping& mem_space_map) -> llvm::LogicalResult {
  rewriter.startOpModification(op);
  auto changed = false;

  for (auto* const input : op.getDpsInputOperands()) {
    changed |= succeeded(broadcastInput(rewriter, op, input, mem_space_map));
  }

  if (!changed) {
    rewriter.cancelOpModification(op);
    return llvm::failure();
  }

  LDBG() << "broadcasted " << mlir::OpWithFlags(op, kSkipRegions);
  rewriter.finalizeOpModification(op);
  return llvm::success();
}

}  // namespace

void KTIRMapAndTilePass::runOnOperation() {
  if (disable_this_pass) {
    return;
  }

  mlir::func::FuncOp func = getOperation();
  mlir::IRRewriter rewriter(func);

  // Collect linalg compute operations.
  llvm::SmallVector<mlir::linalg::LinalgOp> computes;
  func.walk(
      [&](mlir::linalg::GenericOp compute) { computes.push_back(compute); });
  if (computes.empty()) {
    return;
  }

  // Collect only `ktdp.load` ops that feed into a compute operation and
  // `ktdp.store` ops that originate from a compute operation.
  llvm::SmallVector<mlir::ktdp::LoadOp> loads;
  llvm::SmallVector<mlir::ktdp::StoreOp> stores;

  for (auto compute : computes) {
    // Trace backward from compute inputs to find feeding ktdp.load ops.
    for (mlir::OpOperand* input : compute.getDpsInputOperands()) {
      mlir::Value val = input->get();
      while (val) {
        if (auto load = val.getDefiningOp<mlir::ktdp::LoadOp>()) {
          if (!llvm::is_contained(loads, load)) {
            loads.push_back(load);
          }
          break;
        }
        if (auto via = val.getDefiningOp<mlir::ktdf::ViaOp>()) {
          val = via.getOperand();
        } else if (auto extract =
                       val.getDefiningOp<mlir::tensor::ExtractSliceOp>()) {
          val = extract.getSource();
        } else {
          break;
        }
      }
    }

    // Trace forward from compute results to find sinking ktdp.store ops.
    llvm::SmallVector<mlir::Value> worklist(compute->getResults().begin(),
                                            compute->getResults().end());
    while (!worklist.empty()) {
      mlir::Value val = worklist.pop_back_val();
      for (mlir::Operation* user : val.getUsers()) {
        if (auto store = mlir::dyn_cast<mlir::ktdp::StoreOp>(user)) {
          if (!llvm::is_contained(stores, store)) {
            stores.push_back(store);
          }
        } else if (mlir::isa<mlir::ktdf::ViaOp, mlir::tensor::InsertSliceOp,
                             mlir::tensor::ExpandShapeOp>(user)) {
          for (mlir::Value res : user->getResults()) {
            worklist.push_back(res);
          }
        }
      }
    }
  }

  // Obtain the default device and start a mapping.
  auto& default_device = getAnalysis<mlir::ktdf_arch::DefaultDevice>();
  if (!default_device) {
    signalPassFailure();
    return;
  }
  mlir::ktdf_arch::Mapping mapping(default_device.getRef());

  // This pass supports remapping of the memory space attributes.
  AttrMapping mem_space_map;
  if (auto map = default_device->getAttrOfType<mlir::ktdf_arch::MapAttr>(
          "mem_space_mapping");
      map) {
    mem_space_map.insert_range(map);
  }

  // Tile all the compute operations and put them into loop nests that feature
  // loop-carried dependencies.
  llvm::SmallVector<mlir::scf::LoopVector> loop_nests;
  for (auto& op : computes) {
    auto maybe_loops = tile(rewriter, op, mapping);
    if (failed(maybe_loops)) {
      signalPassFailure();
      return;
    }
    if (maybe_loops->empty()) {
      LDBG() << "no loops generated for "
             << mlir::OpWithFlags(op, kSkipRegions);
      continue;
    }

    loop_nests.emplace_back(std::move(*maybe_loops));
    // Break the loop carried `tensor.extract_slice` dependencies.
    // FIXME: This is illegal if we're ever tiling across a reduction dimension.
    breakLoopCarriedDependencies(rewriter, op);
  }

  // Merge `tensor.(insert|extract)_slice` operations before lowering.
  {
    mlir::RewritePatternSet patterns(&getContext());
    mlir::tensor::populateMergeConsecutiveInsertExtractSlicePatterns(patterns);

    if (failed(
            mlir::applyPatternsGreedily(getOperation(), std::move(patterns)))) {
      signalPassFailure();
      return;
    }
  }

  // Lower all `ktdp.(load|store)` operations.
  if (failed(lowerLoadAndStore(rewriter, loads, stores, mem_space_map))) {
    signalPassFailure();
    return;
  }
  loads.clear();
  stores.clear();

  // Remove the loop-carried dependencies altogether.
  for (auto& loop_nest : loop_nests) {
    assert(!loop_nest.empty());
    dropIterArgs(rewriter, loop_nest);
  }

  // FIXME: Since the dropIterArgs and motion transforms are shady, run the
  //        verifier on this function no matter what until we resolve this.
  if (failed(mlir::verify(func, true))) {
    signalPassFailure();
    return;
  }

  // Broadcast compute operands back to target vector size.
  for (auto op : computes) {
    rewriter.setInsertionPoint(op);
    std::ignore = broadcastInputs(rewriter, op, mem_space_map);
  }

  // Clean up all the unused function-level constants that remain.
  for (auto& empty : llvm::make_early_inc_range(func.getOps())) {
    if (mlir::isOpTriviallyDead(&empty)) {
      rewriter.eraseOp(&empty);
    }
  }
}
