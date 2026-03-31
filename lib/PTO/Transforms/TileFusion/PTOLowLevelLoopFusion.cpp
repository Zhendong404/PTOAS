#include "PTO/IR/PTO.h"
#include "PTO/IR/PTO.h"
#include "PTO/Transforms/Passes.h"
#include "../Utils.h"

#include "mlir/Dialect/Arith/IR/Arith.h"
#include "mlir/Dialect/Func/IR/FuncOps.h"
#include "mlir/Dialect/MemRef/IR/MemRef.h"
#include "mlir/Dialect/SCF/IR/SCF.h"
#include "mlir/Dialect/Vector/IR/VectorOps.h"
#include "mlir/IR/Builders.h"
#include "mlir/IR/IRMapping.h"
#include "mlir/Interfaces/SideEffectInterfaces.h"
#include "mlir/Pass/Pass.h"

#include "llvm/ADT/STLExtras.h"

namespace mlir {
namespace pto {
#define GEN_PASS_DEF_PTOLOWLEVELLOOPFUSION
#include "PTO/Transforms/Passes.h.inc"
} // namespace pto
} // namespace mlir

using namespace mlir;

namespace {

// Contract note:
//   PTOLowLevelLoopFusion now runs on VPTO post-lowering `scf.for + pto.*`
//   loop nests that remain inside pto.fusion_region until explicit flatten.
//   A prior vecscope-merge normalization may first sink multiple sibling
//   pto.vecscope bodies into one carrier region. This pass must then stay
//   inside each individual pto.vecscope / pto.strict_vecscope body and must
//   not fuse loop stages across vector-scope boundaries. The matcher below
//   intentionally stays conservative: it only fuses adjacent loop stages with
//   the same loop-header structure and side-effect-free setup scaffolding
//   between them.

struct LoopLevelInfo {
  scf::ForOp loop;
  SmallVector<Operation *, 4> preludeOps;
};

struct StageInfo {
  SmallVector<Operation *, 4> setupOps;
  SmallVector<LoopLevelInfo, 4> levels;
  SmallVector<Operation *, 8> leafOps;

  scf::ForOp getOuterLoop() const { return levels.front().loop; }
  unsigned getDepth() const { return levels.size(); }
};

static bool areEquivalentValues(Value lhs, Value rhs);

static Value mapValueOrSelf(Value value, IRMapping &mapping) {
  return mapping.lookupOrDefault(value);
}

static bool sameForHeader(scf::ForOp lhs, scf::ForOp rhs) {
  return areEquivalentValues(lhs.getLowerBound(), rhs.getLowerBound()) &&
         areEquivalentValues(lhs.getUpperBound(), rhs.getUpperBound()) &&
         areEquivalentValues(lhs.getStep(), rhs.getStep()) &&
         lhs->getAttrs() == rhs->getAttrs();
}

static bool isPureNoRegionOp(Operation *op) {
  return op->getNumRegions() == 0 && isMemoryEffectFree(op);
}

static bool isMovableMemoryPreludeOp(Operation *op) {
  return op->getNumRegions() == 0 && isa<MemoryEffectOpInterface>(op);
}

static bool isSupportedPreludeOp(Operation *op) {
  return isPureNoRegionOp(op) || isMovableMemoryPreludeOp(op);
}

static bool isSupportedLeafOp(Operation *op) { return op->getNumRegions() == 0; }

static bool isInterstageSetupOp(Operation *op) {
  return isPureNoRegionOp(op);
}

static bool areEquivalentOperations(Operation *lhs, Operation *rhs) {
  if (!lhs || !rhs)
    return false;
  if (lhs->getName() != rhs->getName())
    return false;
  if (lhs->getNumRegions() != 0 || rhs->getNumRegions() != 0)
    return false;
  if (lhs->getNumResults() != rhs->getNumResults())
    return false;
  if (lhs->getNumOperands() != rhs->getNumOperands())
    return false;
  if (lhs->getAttrDictionary() != rhs->getAttrDictionary())
    return false;
  if (!llvm::equal(lhs->getResultTypes(), rhs->getResultTypes()))
    return false;

  if (auto lhsDim = dyn_cast<memref::DimOp>(lhs)) {
    auto rhsDim = cast<memref::DimOp>(rhs);
    return lhsDim.getSource().getType() == rhsDim.getSource().getType() &&
           areEquivalentValues(lhsDim.getIndex(), rhsDim.getIndex());
  }

  for (auto [lhsOperand, rhsOperand] :
       llvm::zip(lhs->getOperands(), rhs->getOperands())) {
    if (!areEquivalentValues(lhsOperand, rhsOperand))
      return false;
  }
  return true;
}

static bool areEquivalentValues(Value lhs, Value rhs) {
  if (lhs == rhs)
    return true;
  if (!lhs || !rhs)
    return false;
  if (lhs.getType() != rhs.getType())
    return false;

  auto lhsArg = dyn_cast<BlockArgument>(lhs);
  auto rhsArg = dyn_cast<BlockArgument>(rhs);
  if (lhsArg || rhsArg) {
    return lhsArg && rhsArg && lhsArg.getOwner() == rhsArg.getOwner() &&
           lhsArg.getArgNumber() == rhsArg.getArgNumber();
  }

  return areEquivalentOperations(lhs.getDefiningOp(), rhs.getDefiningOp());
}

static FailureOr<Value> getRootMemRef(Value value) {
  if (!value || !isa<BaseMemRefType>(value.getType()))
    return failure();
  Value root = pto::tracebackMemRef(value);
  if (!root || !isa<BaseMemRefType>(root.getType()))
    return failure();
  return root;
}

static LogicalResult collectAliasRelevantRoots(
    Operation *op, SmallVectorImpl<Value> &roots) {
  if (isMemoryEffectFree(op))
    return success();

  auto effectsOp = dyn_cast<MemoryEffectOpInterface>(op);
  if (!effectsOp)
    return failure();

  SmallVector<SideEffects::EffectInstance<MemoryEffects::Effect>, 4> effects;
  effectsOp.getEffects(effects);
  for (const auto &effect : effects) {
    Value effectValue = effect.getValue();
    if (!effectValue)
      return failure();

    if (!isa<BaseMemRefType>(effectValue.getType())) {
      if (isa<MemoryEffects::Write>(effect.getEffect()))
        return failure();
      continue;
    }

    FailureOr<Value> root = getRootMemRef(effectValue);
    if (failed(root))
      return failure();
    roots.push_back(*root);
  }
  return success();
}

static bool canMovePreludeAcrossPriorStages(Operation *preludeOp,
                                            ArrayRef<StageInfo> priorStages,
                                            llvm::raw_ostream *debugOS) {
  SmallVector<Value, 4> preludeRoots;
  if (failed(collectAliasRelevantRoots(preludeOp, preludeRoots))) {
    if (debugOS)
      *debugOS << "[op-fusion] reject prelude op " << preludeOp->getName()
               << " at " << preludeOp->getLoc()
               << ": touched roots are not alias-analyzable\n";
    return false;
  }
  for (const StageInfo &priorStage : priorStages) {
    for (Operation *leafOp : priorStage.leafOps) {
      SmallVector<Value, 4> leafRoots;
      if (failed(collectAliasRelevantRoots(leafOp, leafRoots))) {
        if (debugOS)
          *debugOS << "[op-fusion] reject prelude op " << preludeOp->getName()
                   << " at " << preludeOp->getLoc()
                   << ": crossed effects of " << leafOp->getName()
                   << " are not alias-analyzable\n";
        return false;
      }
      for (Value preludeRoot : preludeRoots) {
        if (llvm::is_contained(leafRoots, preludeRoot)) {
          if (debugOS)
            *debugOS << "[op-fusion] reject prelude op "
                     << preludeOp->getName() << " at " << preludeOp->getLoc()
                     << ": touched root may alias a prior stage memory op\n";
          return false;
        }
      }
    }
  }

  return true;
}

static bool arePreludeReordersLegal(ArrayRef<StageInfo> stages,
                                    llvm::raw_ostream *debugOS) {
  for (size_t stageIndex = 1; stageIndex < stages.size(); ++stageIndex) {
    ArrayRef<StageInfo> priorStages(stages.data(), stageIndex);
    for (const LoopLevelInfo &level : stages[stageIndex].levels) {
      for (Operation *op : level.preludeOps) {
        if (!canMovePreludeAcrossPriorStages(op, priorStages, debugOS))
          return false;
      }
    }
  }
  return true;
}

static LogicalResult analyzeStage(scf::ForOp outerLoop, StageInfo &stage) {
  scf::ForOp currentLoop = outerLoop;
  while (currentLoop) {
    stage.levels.push_back(LoopLevelInfo{currentLoop, {}});
    LoopLevelInfo &currentLevel = stage.levels.back();

    SmallVector<Operation *, 8> bodyOps;
    scf::ForOp childLoop;
    for (Operation &op : currentLoop.getBody()->without_terminator()) {
      bodyOps.push_back(&op);
      if (auto nestedLoop = dyn_cast<scf::ForOp>(op)) {
        if (childLoop)
          return failure();
        childLoop = nestedLoop;
      }
    }

    if (!childLoop) {
      for (Operation *op : bodyOps) {
        if (!isSupportedLeafOp(op))
          return failure();
        stage.leafOps.push_back(op);
      }
      return failure(stage.leafOps.empty());
    }

    bool seenChildLoop = false;
    for (Operation *op : bodyOps) {
      if (op == childLoop.getOperation()) {
        seenChildLoop = true;
        continue;
      }
      if (seenChildLoop || !isSupportedPreludeOp(op))
        return failure();
      currentLevel.preludeOps.push_back(op);
    }

    currentLoop = childLoop;
  }

  return failure();
}

static SmallVector<StageInfo, 8> collectStageRunFrom(scf::ForOp firstLoop,
                                                     llvm::raw_ostream *debugOS) {
  SmallVector<StageInfo, 8> stages;

  StageInfo firstStage;
  if (failed(analyzeStage(firstLoop, firstStage))) {
    if (debugOS)
      *debugOS << "[op-fusion] reject loop stage at " << firstLoop.getLoc()
               << ": stage analysis failed\n";
    return stages;
  }
  stages.push_back(std::move(firstStage));

  SmallVector<Operation *, 4> pendingSetup;
  for (Operation *op = firstLoop->getNextNode(); op; op = op->getNextNode()) {
    if (auto nextLoop = dyn_cast<scf::ForOp>(op)) {
      StageInfo nextStage;
      nextStage.setupOps = pendingSetup;
      pendingSetup.clear();
      if (failed(analyzeStage(nextLoop, nextStage))) {
        if (debugOS)
          *debugOS << "[op-fusion] stop stage run before " << nextLoop.getLoc()
                   << ": next stage analysis failed\n";
        break;
      }
      stages.push_back(std::move(nextStage));
      continue;
    }

    if (!isInterstageSetupOp(op)) {
      if (debugOS)
        *debugOS << "[op-fusion] stop stage run at op " << op->getName()
                 << "\n";
      break;
    }
    pendingSetup.push_back(op);
  }

  return stages;
}

static bool sameLoopNestShape(const StageInfo &lhs, const StageInfo &rhs) {
  if (lhs.getDepth() != rhs.getDepth())
    return false;
  return llvm::all_of(llvm::zip(lhs.levels, rhs.levels), [](auto pair) {
    return sameForHeader(std::get<0>(pair).loop, std::get<1>(pair).loop);
  });
}

static void cloneOpAndMapResults(OpBuilder &builder, Operation *op,
                                 IRMapping &mapping) {
  Operation *cloned = builder.clone(*op, mapping);
  for (auto [oldRes, newRes] :
       llvm::zip(op->getResults(), cloned->getResults()))
    mapping.map(oldRes, newRes);
}

static void appendMappedValues(ValueRange values, IRMapping &mapping,
                               SmallVectorImpl<Value> &mappedValues) {
  for (Value value : values)
    mappedValues.push_back(mapValueOrSelf(value, mapping));
}

static scf::ForOp buildFusedLoopNestAtLevel(OpBuilder &builder,
                                            MutableArrayRef<StageInfo> stages,
                                            MutableArrayRef<IRMapping> mappings,
                                            unsigned levelIndex) {
  scf::ForOp firstLoop = stages.front().levels[levelIndex].loop;

  SmallVector<Value, 8> fusedInitArgs;
  for (auto [stageIndex, stage] : llvm::enumerate(stages))
    appendMappedValues(ValueRange(stage.levels[levelIndex].loop.getInitArgs()),
                       mappings[stageIndex], fusedInitArgs);

  auto fusedLoop = builder.create<scf::ForOp>(
      firstLoop.getLoc(),
      mapValueOrSelf(firstLoop.getLowerBound(), mappings.front()),
      mapValueOrSelf(firstLoop.getUpperBound(), mappings.front()),
      mapValueOrSelf(firstLoop.getStep(), mappings.front()), fusedInitArgs);
  fusedLoop->setAttrs(firstLoop->getAttrs());

  unsigned iterArgOffset = 0;
  for (auto [stageIndex, stage] : llvm::enumerate(stages)) {
    scf::ForOp originalLoop = stage.levels[levelIndex].loop;
    mappings[stageIndex].map(originalLoop.getInductionVar(),
                             fusedLoop.getInductionVar());
    for (auto [argIndex, originalArg] :
         llvm::enumerate(originalLoop.getRegionIterArgs()))
      mappings[stageIndex].map(
          originalArg, fusedLoop.getRegionIterArgs()[iterArgOffset + argIndex]);
    iterArgOffset += originalLoop.getRegionIterArgs().size();
  }

  OpBuilder bodyBuilder = OpBuilder::atBlockBegin(fusedLoop.getBody());
  for (auto [stageIndex, stage] : llvm::enumerate(stages))
    for (Operation *op : stage.levels[levelIndex].preludeOps)
      cloneOpAndMapResults(bodyBuilder, op, mappings[stageIndex]);

  if (levelIndex + 1 < stages.front().getDepth()) {
    (void)buildFusedLoopNestAtLevel(bodyBuilder, stages, mappings,
                                    levelIndex + 1);
  } else {
    for (auto [stageIndex, stage] : llvm::enumerate(stages))
      for (Operation *op : stage.leafOps)
        cloneOpAndMapResults(bodyBuilder, op, mappings[stageIndex]);
  }

  SmallVector<Value, 8> fusedYieldOperands;
  for (auto [stageIndex, stage] : llvm::enumerate(stages)) {
    auto originalYield = cast<scf::YieldOp>(
        stage.levels[levelIndex].loop.getBody()->getTerminator());
    appendMappedValues(ValueRange(originalYield.getOperands()),
                       mappings[stageIndex],
                       fusedYieldOperands);
  }

  if (auto fusedYield =
          dyn_cast<scf::YieldOp>(fusedLoop.getBody()->getTerminator())) {
    fusedYield->setOperands(fusedYieldOperands);
  } else {
    OpBuilder yieldBuilder = OpBuilder::atBlockEnd(fusedLoop.getBody());
    yieldBuilder.create<scf::YieldOp>(firstLoop.getLoc(), fusedYieldOperands);
  }

  unsigned resultOffset = 0;
  for (auto [stageIndex, stage] : llvm::enumerate(stages)) {
    scf::ForOp originalLoop = stage.levels[levelIndex].loop;
    for (Value originalResult : originalLoop.getResults())
      mappings[stageIndex].map(originalResult,
                               fusedLoop.getResults()[resultOffset++]);
  }

  return fusedLoop;
}

static bool fuseStageRun(SmallVectorImpl<StageInfo> &stages,
                         llvm::raw_ostream *debugOS) {
  if (stages.size() < 2) {
    if (debugOS)
      *debugOS << "[op-fusion] reject loop run: need at least 2 stages, got "
               << stages.size() << "\n";
    return false;
  }

  StageInfo &first = stages.front();
  for (StageInfo &stage : llvm::drop_begin(stages)) {
    if (!sameLoopNestShape(first, stage)) {
      if (debugOS)
        *debugOS << "[op-fusion] reject loop run: loop nest shape mismatch\n";
      return false;
    }
  }
  if (!arePreludeReordersLegal(stages, debugOS))
    return false;

  OpBuilder blockBuilder(first.getOuterLoop());
  SmallVector<IRMapping, 8> stageMappings(stages.size());
  auto fusedOuterLoop =
      buildFusedLoopNestAtLevel(blockBuilder, stages, stageMappings, 0);

  for (StageInfo &stage : llvm::drop_begin(stages))
    for (Operation *setupOp : stage.setupOps)
      setupOp->moveBefore(fusedOuterLoop);

  for (StageInfo &stage : llvm::reverse(stages))
    stage.getOuterLoop().erase();

  return true;
}

static bool fuseStageRunsInBlock(Block &block, llvm::raw_ostream *debugOS) {
  bool changed = false;
  bool localChange = true;

  while (localChange) {
    localChange = false;
    for (Operation &op : block) {
      auto firstLoop = dyn_cast<scf::ForOp>(op);
      if (!firstLoop)
        continue;

      SmallVector<StageInfo, 8> stages =
          collectStageRunFrom(firstLoop, debugOS);
      if (!fuseStageRun(stages, debugOS))
        continue;

      changed = true;
      localChange = true;
      break;
    }
  }

  return changed;
}

struct PTOLowLevelLoopFusionPass
    : public pto::impl::PTOLowLevelLoopFusionBase<PTOLowLevelLoopFusionPass> {
  using pto::impl::PTOLowLevelLoopFusionBase<
      PTOLowLevelLoopFusionPass>::PTOLowLevelLoopFusionBase;

  void runOnOperation() override {
    ModuleOp module = getOperation();

    int fusedFuncs = 0;
    for (func::FuncOp func : module.getOps<func::FuncOp>()) {
      if (func.isExternal())
        continue;
      if (func.getSymName().starts_with("__pto_oplib_"))
        continue;
      if (func.empty())
        continue;

      bool changed = false;
      func.walk([&](pto::FusionRegionOp fusionRegion) {
        fusionRegion.walk([&](pto::VecScopeOp vecScope) {
          if (!vecScope.getBody().empty())
            changed |= fuseStageRunsInBlock(vecScope.getBody().front(),
                                            debug ? &llvm::errs() : nullptr);
        });
        fusionRegion.walk([&](pto::StrictVecScopeOp vecScope) {
          if (!vecScope.getBody().empty())
            changed |= fuseStageRunsInBlock(vecScope.getBody().front(),
                                            debug ? &llvm::errs() : nullptr);
        });
      });
      if (changed)
        ++fusedFuncs;
    }

    if (debug) {
      llvm::errs() << "[op-fusion] low-level loop fusion changed " << fusedFuncs
                   << " function(s)\n";
    }
  }
};

} // namespace

std::unique_ptr<Pass> mlir::pto::createPTOLowLevelLoopFusionPass(
    const PTOLowLevelLoopFusionOptions &options) {
  return std::make_unique<PTOLowLevelLoopFusionPass>(options);
}
