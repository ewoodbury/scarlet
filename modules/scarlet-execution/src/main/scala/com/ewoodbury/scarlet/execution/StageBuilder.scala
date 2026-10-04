package com.ewoodbury.scarlet.execution

import scala.collection.mutable

import com.ewoodbury.scarlet.core.{Partition, Plan, ScarletConf, StageId}

/**
 * Builds stage execution graphs from plans, handling both narrow transformations and shuffle
 * boundaries for wide transformations. Finished graphs are checked by [[StageGraphValidation]].
 *
 * Named erasure boundary: plan element types are erased when operations are accumulated into
 * stages, and materialization casts back to the closure types the executor runs. Safe because Plan
 * and Operation carry the same types for any given pipeline position.
 */
@SuppressWarnings(
  Array(
    "org.wartremover.warts.Any",
    "org.wartremover.warts.AsInstanceOf",
    "org.wartremover.warts.MutableDataStructures",
    "org.wartremover.warts.Equals",
    "org.wartremover.warts.RedundantAsInstanceOf",
  ),
)
object StageBuilder:

  /**
   * Information about a stage in the execution graph.
   *
   * `outputPartitioning` is set by shuffle stages and preserved or updated by narrow ops. It is
   * not inferred from record order. See [[PartitioningInfo]].
   */
  case class StageInfo(
      id: StageId,
      stage: Stage[_, _],
      inputSources: Seq[InputSource], // What this stage reads from
      isShuffleStage: Boolean,
      /** For shuffle stages, the wide operation this stage executes. */
      wideOp: Option[WideOp],
      outputPartitioning: Option[PartitioningInfo],
  )

  /**
   * Represents where a stage gets its input data from.
   */
  sealed trait InputSource
  case class SourceInput(partitions: Seq[Partition[_]]) extends InputSource

  /**
   * Side tag to disambiguate multi-input wide operations (e.g., join/cogroup).
   */
  enum Side:
    case Left, Right

  /**
   * Unified shuffle input that can handle both single-input and multi-input shuffle operations.
   * The optional side parameter disambiguates multi-input operations (e.g., join/cogroup).
   */
  case class ShuffleInput(stageId: StageId, side: Option[Side], numPartitions: Int)
      extends InputSource

  /**
   * References the runtime output of a previously computed stage. Used for operations like union
   * that need to concatenate upstream results without reshuffling.
   */
  case class StageOutput(stageId: StageId) extends InputSource

  /**
   * Complete stage execution graph with dependencies.
   */
  case class StageGraph(
      stages: Map[StageId, StageInfo],
      dependencies: Map[StageId, Set[StageId]], // stage ID -> dependent stage IDs
      finalStageId: StageId,
  )

  /**
   * Immutable stage draft for accumulating operations during stage construction. All fields are
   * immutable; mutations create new instances.
   */
  private case class StageDraft(
      id: StageId,
      ops: Vector[Operation[Any, Any]],
      inputSources: Seq[InputSource],
      isShuffle: Boolean,
      /** Set exactly when `isShuffle` is true: the wide operation this stage executes. */
      shuffleMeta: Option[WideOp],
      outputPartitioning: Option[PartitioningInfo],
  )

  // Per-build context to generate monotonically increasing stage IDs without global/shared state
  @SuppressWarnings(Array("org.wartremover.warts.Var"))
  private final case class BuildContext(var nextId: Int):
    def freshId(): StageId =
      val id = StageId(nextId)
      nextId = nextId + 1
      id

  /**
   * Encapsulated mutation helpers to centralize stage builder and dependency management. Provides
   * single points for invariant checking and reduces accidental misuse.
   */
  private def putBuilder(
      builderMap: mutable.Map[StageId, StageDraft],
      builder: StageDraft,
  ): Unit = {
    builderMap(builder.id) = builder
  }

  private def putNewBuilder(
      builderMap: mutable.Map[StageId, StageDraft],
      builder: StageDraft,
  ): Unit = {
    // Check invariant: no duplicate stage IDs
    require(
      !builderMap.contains(builder.id),
      s"Stage ID ${builder.id} already exists in builder map",
    )
    builderMap(builder.id) = builder
  }

  private def addDependency(
      dependencies: mutable.Map[StageId, mutable.Set[StageId]],
      child: StageId,
      parent: StageId,
  ): Unit = {
    require(child != parent, s"Stage $child cannot depend on itself")
    dependencies.getOrElseUpdate(child, mutable.Set.empty) += parent
  }

  /**
   * Builds a complete stage graph from a plan using the unified builder approach. This replaces
   * the old recursive approach with a more structured operation accumulation.
   */
  def buildStageGraph[A](plan: Plan[A]): StageGraph = {
    val ctx = BuildContext(0)
    val builderMap = mutable.Map[StageId, StageDraft]()
    val dependencies = mutable.Map[StageId, mutable.Set[StageId]]()

    val (finalStageId, _) = buildStagesFromPlan(ctx, plan, builderMap, dependencies)

    // Convert StageDraft instances to StageInfo instances
    val stageMap = mutable.Map[StageId, StageInfo]()
    builderMap.foreachEntry { (stageId, builder) =>
      val stage = if (builder.isShuffle) {
        // For shuffle stages, create placeholder stage (will be replaced by actual shuffle logic)
        Stage.SingleOpStage[Any, Any](identity)
      } else {
        // For narrow stages, materialize the operation vector into a concrete stage
        // If there are no operations (e.g., source stages), create an identity stage
        if (builder.ops.isEmpty) {
          Stage.SingleOpStage[Any, Any](identity)
        } else {
          materialize(builder.ops)
        }
      }

      stageMap(stageId) = StageInfo(
        id = stageId,
        stage = stage,
        inputSources = builder.inputSources,
        isShuffleStage = builder.isShuffle,
        wideOp = builder.shuffleMeta,
        outputPartitioning = builder.outputPartitioning,
      )
    }

    val stageGraph = StageGraph(
      stageMap.toMap,
      dependencies.map { case (k, v) => k -> v.toSet }.toMap,
      finalStageId,
    )

    // Post-build validation
    validateStageGraph(stageGraph)

    stageGraph
  }

  /**
   * Validates StageGraph invariants to catch errors early. Checks for consistency issues that
   * could cause runtime failures.
   */
  private[execution] def validateStageGraph(graph: StageGraph): Unit =
    StageGraphValidation.validate(graph)

  /**
   * Materializes a vector of operations into a concrete Stage form.
   *
   * This function converts a sequence of Operation ADT instances into executable Stage objects. It
   * employs several optimization strategies:
   *
   *   1. **Single Operation Optimization**: For single operations, returns the operation directly
   *      without unnecessary chaining to minimize overhead.
   *   2. **Efficient Chaining**: For multiple operations, uses a left fold to build the chain,
   *      creating ChainedStage instances that compose operations efficiently.
   *
   * @param ops
   *   Non-empty vector of operations to materialize
   * @return
   *   A concrete Stage that can be executed
   * @throws UnsupportedOperationException
   *   if the operation vector contains wide operations (shuffle operations) that cannot be
   *   materialized as narrow stages
   * @note
   *   This function only handles narrow operations. Wide operations should be processed through
   *   separate shuffle stages before materialization.
   */
  private[execution] def materialize(ops: Vector[Operation[Any, Any]]): Stage[Any, Any] = {
    require(ops.nonEmpty, "Cannot materialize empty operation vector")

    // For single operations, return the operation directly without chaining
    if (ops.length == 1) {
      ops.headOption match {
        case Some(op) => createStageFromOp(op)
        case None =>
          throw new IllegalStateException(
            "Single operation vector unexpectedly empty after length check. " +
              "This indicates a concurrent modification or internal error.",
          )
      }
    } else {
      // For multiple operations, build the chain efficiently
      ops.headOption match {
        case Some(firstOp) =>
          ops.drop(1).foldLeft(createStageFromOp(firstOp)) { (stage, op) =>
            chainOperationUnsafe(stage, op)
          }
        case None =>
          throw new IllegalStateException(
            "Multiple operation vector unexpectedly empty after validation. " +
              s"Original vector length: ${ops.length}. " +
              "This indicates a concurrent modification or internal error.",
          )
      }
    }
  }

  /**
   * Single controlled point of type erasure where it's unavoidable. This is the only place where
   * we deal with Any types and casting, keeping type safety elsewhere.
   */
  private def createStageFromOpUnsafe(op: Operation[Any, Any]): Stage[Any, Any] = {
    op match {
      case MapOp(f) => Stage.map(f)
      case FilterOp(p) => Stage.filter(p)
      case FlatMapOp(f) => Stage.flatMap(f)
      case DistinctOp() => Stage.distinct[Any]
      case MapPartitionsOp(f) => Stage.mapPartitions(f)

      // Bypassed wide ops are appended as no-op narrow stages: the upstream data is already
      // partitioned the way the operation wants it.
      case PartitionByLocalOp(_) => Stage.identity[Any]
      case _: RepartitionOp[_] => Stage.identity[Any]
      case _: CoalesceOp[_] => Stage.identity[Any]

      // Key-value operations - controlled type erasure point
      case _: KeysOp[_, _] =>
        Stage.keys[Any, Any].asInstanceOf[Stage[Any, Any]]
      case _: ValuesOp[_, _] =>
        Stage.values[Any, Any].asInstanceOf[Stage[Any, Any]]
      case MapValuesOp(f) =>
        Stage
          .mapValues[Any, Any, Any](f.asInstanceOf[Any => Any])
          .asInstanceOf[Stage[Any, Any]]
      case FilterKeysOp(p) =>
        Stage
          .filterKeys[Any, Any](p.asInstanceOf[Any => Boolean])
          .asInstanceOf[Stage[Any, Any]]
      case FilterValuesOp(p) =>
        Stage
          .filterValues[Any, Any](p.asInstanceOf[Any => Boolean])
          .asInstanceOf[Stage[Any, Any]]
      case FlatMapValuesOp(f) =>
        Stage
          .flatMapValues[Any, Any, Any](f.asInstanceOf[Any => IterableOnce[Any]])
          .asInstanceOf[Stage[Any, Any]]
      case _: GroupByKeyLocalOp[_, _] =>
        Stage.groupByKeyLocal[Any, Any].asInstanceOf[Stage[Any, Any]]
      case ReduceByKeyLocalOp(reduceFunc) =>
        Stage
          .reduceByKeyLocal[Any, Any](reduceFunc.asInstanceOf[(Any, Any) => Any])
          .asInstanceOf[Stage[Any, Any]]

      case _ => throw new UnsupportedOperationException(s"Cannot create stage from operation: $op")
    }
  }

  /**
   * Helper function to chain an operation onto an existing stage. This function encapsulates the
   * pattern matching for operation chaining and eliminates the need for unsafe type casting where
   * possible.
   */
  private def chainOperationUnsafe(
      stage: Stage[Any, Any],
      op: Operation[Any, Any],
  ): Stage[Any, Any] = {
    Stage.ChainedStage(stage, createStageFromOpUnsafe(op))
  }

  /**
   * Creates a concrete Stage object from a single Operation ADT instance.
   *
   * This method serves as the bridge between the high-level Operation ADT and the concrete Stage
   * implementations that can be executed by the runtime. It pattern matches on the operation type
   * and delegates to the appropriate Stage constructor.
   *
   * The method handles all narrow transformation operations including:
   *   - Basic transformations: MapOp, FilterOp, FlatMapOp, DistinctOp
   *   - Key-value operations: KeysOp, ValuesOp, MapValuesOp, FilterKeysOp, FilterValuesOp,
   *     FlatMapValuesOp
   *   - Partition operations: MapPartitionsOp
   *   - Local/bypass operations: GroupByKeyLocalOp, ReduceByKeyLocalOp, PartitionByLocalOp
   *
   * This method is optimized for creating individual stages and is more efficient than
   * materialize() when dealing with single operations, as it avoids unnecessary ChainedStage
   * wrapping.
   *
   * @param op
   *   The Operation to convert into a Stage
   * @return
   *   A concrete Stage[Any, Any] that can be executed
   * @throws UnsupportedOperationException
   *   if the operation is a wide operation that requires shuffle boundaries
   * @note
   *   This method only supports narrow operations. Wide operations should be handled through
   *   shuffle stages created by createShuffleStageUnified().
   */
  private def createStageFromOp(op: Operation[Any, Any]): Stage[Any, Any] = {
    createStageFromOpUnsafe(op)
  }

  /**
   * Core recursive method that traverses a Plan tree and builds stage graphs with operation
   * accumulation.
   *
   * This method implements the unified stage building algorithm that processes Plan nodes
   * recursively, accumulating narrow operations into stages and creating shuffle boundaries for
   * wide operations.
   *
   * The method handles three main categories of Plan nodes:
   *
   *   1. **Data Sources (Plan.Source)**:
   *      - Base case that creates initial stage builders for data partitions
   *      - Sets up source partitioning metadata based on partition count
   *      - Returns the stage ID and original Plan for dependency tracking
   *   2. **Narrow Transformations**:
   *      - Accumulates operations using appendOperation() when possible
   *      - Creates new stages when chaining is not feasible
   *      - Handles: MapOp, FilterOp, FlatMapOp, DistinctOp, KeysOp, ValuesOp, MapValuesOp,
   *        FilterKeysOp, FilterValuesOp, FlatMapValuesOp, MapPartitionsOp
   *   3. **Multi-input Operations**:
   *      - UnionOp: Creates a new stage that reads from both input stages
   *      - Preserves no partitioning metadata due to input consolidation
   *   4. **Wide Transformations (Shuffle Operations)**:
   *      - GroupByKeyOp, ReduceByKeyOp: Supports shuffle bypass optimization when already
   *        partitioned correctly
   *      - SortByOp, PartitionByOp, RepartitionOp, CoalesceOp: Always creates shuffle boundaries
   *      - JoinOp, CoGroupOp: Multi-input wide operations with side tagging for disambiguation
   *      - Uses WideOp metadata structures for shuffle execution planning
   *
   * **Optimization Strategies**:
   *   - Shuffle Bypass: For operations like groupByKey/reduceByKey, checks if upstream
   *     partitioning matches requirements and bypasses shuffle when possible
   *   - Operation Chaining: Accumulates multiple narrow operations into single stages to reduce
   *     overhead
   *   - Dependency Tracking: Builds comprehensive dependency graph for execution ordering
   *
   * @param ctx
   *   BuildContext for generating unique stage IDs
   * @param plan
   *   The Plan node to process recursively
   * @param builderMap
   *   Mutable map accumulating stage builders (modified in place)
   * @param dependencies
   *   Mutable map tracking stage dependencies (modified in place)
   * @tparam A
   *   Type parameter of the Plan (preserved for type safety)
   * @return
   *   Tuple of (StageId, Option[Plan]) where StageId is the resulting stage identifier, and
   *   Option[Plan] contains the original Plan for shuffle operation metadata
   * @note
   *   This method modifies builderMap and dependencies in place for efficiency
   * @note
   *   The return Plan is crucial for shuffle stages to preserve original operation metadata
   */
  private def buildStagesFromPlan[A](
      ctx: BuildContext,
      plan: Plan[A],
      builderMap: mutable.Map[StageId, StageDraft],
      dependencies: mutable.Map[StageId, mutable.Set[StageId]],
  ): (StageId, Option[Plan[_]]) = {
    plan match {
      // Base case: data source - don't create a stage yet, let operations chain to it
      case source: Plan.Source[_] =>
        val stageId = ctx.freshId()
        putNewBuilder(
          builderMap,
          StageDraft(
            id = stageId,
            ops = Vector.empty[
              Operation[Any, Any],
            ], // No operations for source - operations will be chained here
            inputSources = Seq(SourceInput(source.partitions)),
            isShuffle = false,
            shuffleMeta = None,
            outputPartitioning = Some(PartitioningInfo.unknown(source.partitions.size)),
          ),
        )
        (stageId, Some(source))

      // Narrow transformations - accumulate operations or create new stages
      case Plan.MapOp(sourcePlan, f) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.FilterOp(sourcePlan, p) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.FlatMapOp(sourcePlan, f) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.DistinctOp(sourcePlan) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.KeysOp(sourcePlan) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.ValuesOp(sourcePlan) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.MapValuesOp(sourcePlan, f) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.FilterKeysOp(sourcePlan, p) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.FilterValuesOp(sourcePlan, p) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.FlatMapValuesOp(sourcePlan, f) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.MapPartitionsOp(sourcePlan, f) =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sourcePlan, builderMap, dependencies)
        val resultId = appendOperation(
          ctx,
          sourceStageId,
          Operation.fromPlan(plan),
          builderMap,
          dependencies,
        )
        (resultId, Some(plan))

      case Plan.UnionOp(left, right) =>
        val (leftStageId, _) = buildStagesFromPlan(ctx, left, builderMap, dependencies)
        val (rightStageId, _) = buildStagesFromPlan(ctx, right, builderMap, dependencies)

        // Union creates a new narrow stage that reads outputs from both input stages
        val unionStageId = ctx.freshId()
        putNewBuilder(
          builderMap,
          StageDraft(
            id = unionStageId,
            ops = Vector.empty[Operation[Any, Any]], // No operations, just union of inputs
            inputSources = Seq(StageOutput(leftStageId), StageOutput(rightStageId)),
            isShuffle = false,
            shuffleMeta = None,
            outputPartitioning = None, // Union doesn't preserve partitioning
          ),
        )

        addDependency(dependencies, unionStageId, leftStageId)
        addDependency(dependencies, unionStageId, rightStageId)
        (unionStageId, Some(plan))

      // Wide transformations (create shuffle boundaries)
      case groupByKey: Plan.GroupByKeyOp[_, _] =>
        val (sourceStageId, _) =
          buildStagesFromPlan(ctx, groupByKey.source, builderMap, dependencies)
        val src = builderMap(sourceStageId)
        val defaultN = ScarletConf.get.defaultShufflePartitions

        if (Operation.canBypassShuffle(groupByKey, src.outputPartitioning, ScarletConf.get)) {
          // Add local groupByKey operation to existing stage since shuffle can be bypassed
          val resultId = appendOperation(
            ctx,
            sourceStageId,
            GroupByKeyLocalOp[Any, Any]().asInstanceOf[Operation[Any, Any]],
            builderMap,
            dependencies,
          )
          (resultId, Some(groupByKey))
        } else {
          val shuffleId = createShuffleStageUnified(
            ctx,
            Seq(sourceStageId),
            GroupByKeyWideOp(
              SimpleWideOpMeta(
                kind = WideOpKind.GroupByKey,
                numPartitions = defaultN,
              ),
            ),
            builderMap,
            dependencies,
          )
          (shuffleId, Some(groupByKey))
        }

      case reduceByKey: Plan.ReduceByKeyOp[_, _] =>
        val (sourceStageId, _) =
          buildStagesFromPlan(ctx, reduceByKey.source, builderMap, dependencies)
        val src = builderMap(sourceStageId)
        val defaultN = ScarletConf.get.defaultShufflePartitions

        if (Operation.canBypassShuffle(reduceByKey, src.outputPartitioning, ScarletConf.get)) {
          // Add local reduceByKey operation to existing stage since shuffle can be bypassed
          val resultId = appendOperation(
            ctx,
            sourceStageId,
            ReduceByKeyLocalOp[Any, Any](reduceByKey.reduceFunc.asInstanceOf[(Any, Any) => Any])
              .asInstanceOf[Operation[Any, Any]],
            builderMap,
            dependencies,
          )
          (resultId, Some(reduceByKey))
        } else {
          val shuffleId = createShuffleStageUnified(
            ctx,
            Seq(sourceStageId),
            ReduceByKeyWideOp(
              ReduceWideOpMeta(
                numPartitions = defaultN,
                reduceFunc = reduceByKey.reduceFunc,
              ),
            ),
            builderMap,
            dependencies,
          )
          (shuffleId, Some(reduceByKey))
        }

      case sortBy: Plan.SortByOp[_, _] =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, sortBy.source, builderMap, dependencies)
        val n = ScarletConf.get.defaultShufflePartitions
        val shuffleId = createShuffleStageUnified(
          ctx,
          Seq(sourceStageId),
          SortByWideOp(
            SortWideOpMeta(
              numPartitions = n,
              keyFunc = sortBy.keyFunc,
              ordering = sortBy.ordering,
            ),
          ),
          builderMap,
          dependencies,
        )
        (shuffleId, Some(sortBy))

      case pby: Plan.PartitionByOp[_, _] =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, pby.source, builderMap, dependencies)
        val src = builderMap(sourceStageId)

        if (Operation.canBypassShuffle(pby, src.outputPartitioning, ScarletConf.get)) {
          val resultId = appendOperation(
            ctx,
            sourceStageId,
            PartitionByLocalOp[Any, Any](pby.numPartitions).asInstanceOf[Operation[Any, Any]],
            builderMap,
            dependencies,
          )
          (resultId, Some(pby))
        } else {
          val shuffleId = createShuffleStageUnified(
            ctx,
            Seq(sourceStageId),
            PartitionByWideOp(
              SimpleWideOpMeta(
                kind = WideOpKind.PartitionBy,
                numPartitions = pby.numPartitions,
              ),
            ),
            builderMap,
            dependencies,
          )
          (shuffleId, Some(pby))
        }

      case rep: Plan.RepartitionOp[_] =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, rep.source, builderMap, dependencies)
        val src = builderMap(sourceStageId)

        if (Operation.canBypassShuffle(rep, src.outputPartitioning, ScarletConf.get)) {
          val resultId = appendOperation(
            ctx,
            sourceStageId,
            RepartitionOp[Any](rep.numPartitions),
            builderMap,
            dependencies,
          )
          (resultId, Some(rep))
        } else {
          val shuffleId = createShuffleStageUnified(
            ctx,
            Seq(sourceStageId),
            RepartitionWideOp(
              SimpleWideOpMeta(
                kind = WideOpKind.Repartition,
                numPartitions = rep.numPartitions,
              ),
            ),
            builderMap,
            dependencies,
          )
          (shuffleId, Some(rep))
        }

      case coal: Plan.CoalesceOp[_] =>
        val (sourceStageId, _) = buildStagesFromPlan(ctx, coal.source, builderMap, dependencies)
        val src = builderMap(sourceStageId)

        if (Operation.canBypassShuffle(coal, src.outputPartitioning, ScarletConf.get)) {
          val resultId = appendOperation(
            ctx,
            sourceStageId,
            CoalesceOp[Any](coal.numPartitions),
            builderMap,
            dependencies,
          )
          (resultId, Some(coal))
        } else {
          val shuffleId = createShuffleStageUnified(
            ctx,
            Seq(sourceStageId),
            CoalesceWideOp(
              SimpleWideOpMeta(
                kind = WideOpKind.Coalesce,
                numPartitions = coal.numPartitions,
              ),
            ),
            builderMap,
            dependencies,
          )
          (shuffleId, Some(coal))
        }

      case joinOp: Plan.JoinOp[_, _, _] =>
        val (leftStageId, _) = buildStagesFromPlan(ctx, joinOp.left, builderMap, dependencies)
        val (rightStageId, _) = buildStagesFromPlan(ctx, joinOp.right, builderMap, dependencies)

        val numPartitions = ScarletConf.get.defaultShufflePartitions
        val shuffleId = createShuffleStageUnified(
          ctx,
          Seq(leftStageId, rightStageId),
          JoinWideOp(
            SimpleWideOpMeta(
              kind = WideOpKind.Join,
              numPartitions = numPartitions,
              joinStrategy = joinOp.joinStrategy,
              sides = Seq(Side.Left, Side.Right),
            ),
          ),
          builderMap,
          dependencies,
        )
        (shuffleId, Some(joinOp))

      case cogroupOp: Plan.CoGroupOp[_, _, _] =>
        val (leftStageId, _) = buildStagesFromPlan(ctx, cogroupOp.left, builderMap, dependencies)
        val (rightStageId, _) = buildStagesFromPlan(ctx, cogroupOp.right, builderMap, dependencies)

        val numPartitions = ScarletConf.get.defaultShufflePartitions
        val shuffleId = createShuffleStageUnified(
          ctx,
          Seq(leftStageId, rightStageId),
          CoGroupWideOp(
            SimpleWideOpMeta(
              kind = WideOpKind.CoGroup,
              numPartitions = numPartitions,
              sides = Seq(Side.Left, Side.Right),
            ),
          ),
          builderMap,
          dependencies,
        )
        (shuffleId, Some(cogroupOp))
    }
  }

  /**
   * Appends a narrow operation to an existing stage or creates a new stage if needed. This handles
   * the logic of when operations can be chained vs when new stages are required. Returns the
   * StageId that will produce the result (could be the source stage or a new one).
   */
  private def appendOperation(
      ctx: BuildContext,
      sourceStageId: StageId,
      op: Operation[Any, Any],
      builderMap: mutable.Map[StageId, StageDraft],
      dependencies: mutable.Map[StageId, mutable.Set[StageId]],
  ): StageId = {
    val sourceBuilder = builderMap(sourceStageId)

    if (sourceBuilder.isShuffle) {
      // Can't extend a shuffle stage, create a new narrow stage
      val newStageId = ctx.freshId()
      val newBuilder = StageDraft(
        id = newStageId,
        ops = Vector(op),
        inputSources = Seq(StageOutput(sourceStageId)),
        isShuffle = false,
        shuffleMeta = None,
        outputPartitioning = updatePartitioning(sourceBuilder.outputPartitioning, op),
      )
      putNewBuilder(builderMap, newBuilder)

      // Add dependency: new stage depends on source stage
      addDependency(dependencies, newStageId, sourceStageId)
      newStageId
    } else {
      // Narrow ops can chain onto any non-shuffle stage: ops run per partition of the stage's
      // output, which is valid for single-input stages and for concatenation stages (union).
      val canChain = sourceBuilder.inputSources.forall {
        case _: SourceInput => true
        case _: StageOutput => true
        case _: ShuffleInput => false
      }

      if (canChain) {
        // Extend the existing stage by appending the operation
        val updatedOps = sourceBuilder.ops :+ op
        val updatedBuilder = sourceBuilder.copy(
          ops = updatedOps,
          outputPartitioning = updatePartitioning(sourceBuilder.outputPartitioning, op),
        )
        putBuilder(builderMap, updatedBuilder)
        sourceStageId
      } else {
        // Create a new stage that reads the source stage's computed output
        val newStageId = ctx.freshId()
        val newBuilder = StageDraft(
          id = newStageId,
          ops = Vector(op),
          inputSources = Seq(StageOutput(sourceStageId)),
          isShuffle = false,
          shuffleMeta = None,
          outputPartitioning = updatePartitioning(sourceBuilder.outputPartitioning, op),
        )
        putNewBuilder(builderMap, newBuilder)
        addDependency(dependencies, newStageId, sourceStageId)
        newStageId
      }
    }
  }

  /**
   * Creates a shuffle stage using the unified builder approach.
   */
  @SuppressWarnings(Array("org.wartremover.warts.SeqApply", "org.wartremover.warts.IterableOps"))
  private def createShuffleStageUnified(
      ctx: BuildContext,
      upstreamIds: Seq[StageId],
      wideOp: WideOp,
      builderMap: mutable.Map[StageId, StageDraft],
      dependencies: mutable.Map[StageId, mutable.Set[StageId]],
  ): StageId = {
    val shuffleStageId = ctx.freshId()

    // Get metadata from the WideOp
    val meta = wideOp match {
      case GroupByKeyWideOp(m) => m
      case ReduceByKeyWideOp(m) => m
      case SortByWideOp(m) => m
      case PartitionByWideOp(m) => m
      case RepartitionWideOp(m) => m
      case CoalesceWideOp(m) => m
      case JoinWideOp(m) => m
      case CoGroupWideOp(m) => m
    }

    // Create shuffle input sources based on operation type
    val shuffleInputSources = meta.kind match {
      case WideOpKind.Join | WideOpKind.CoGroup =>
        // Multi-input operations need sides
        require(upstreamIds.length == 2, s"${meta.kind} requires exactly 2 upstream stages")
        require(meta.sides.length == 2, s"${meta.kind} requires exactly 2 sides")
        Seq(
          ShuffleInput(upstreamIds(0), Some(meta.sides(0)), meta.numPartitions),
          ShuffleInput(upstreamIds(1), Some(meta.sides(1)), meta.numPartitions),
        )
      case _ =>
        // Single-input operations
        require(upstreamIds.length == 1, s"${meta.kind} requires exactly 1 upstream stage")
        upstreamIds.headOption match {
          case Some(upstreamId) => Seq(ShuffleInput(upstreamId, None, meta.numPartitions))
          case None =>
            throw new IllegalStateException(
              s"${meta.kind} operation missing required upstream stage",
            )
        }
    }

    // Keyed shuffles are hash. sortBy is range-ordered.
    // repartition and coalesce only promise a width: the writer hashes the element.
    val outputPartitioning = meta.kind match {
      case WideOpKind.GroupByKey | WideOpKind.ReduceByKey | WideOpKind.PartitionBy |
          WideOpKind.Join | WideOpKind.CoGroup =>
        Some(PartitioningInfo.hash(meta.numPartitions))
      case WideOpKind.SortBy =>
        Some(PartitioningInfo.rangeSorted(meta.numPartitions))
      case WideOpKind.Repartition =>
        // The writer hashes the element. That is not pair-key hash and not round-robin.
        Some(PartitioningInfo.unknown(meta.numPartitions))
      case WideOpKind.Coalesce =>
        Some(PartitioningInfo.unknown(meta.numPartitions))
    }

    putNewBuilder(
      builderMap,
      StageDraft(
        id = shuffleStageId,
        ops = Vector.empty[Operation[Any, Any]], // Shuffle stages don't have narrow operations
        inputSources = shuffleInputSources,
        isShuffle = true,
        shuffleMeta = Some(wideOp),
        outputPartitioning = outputPartitioning,
      ),
    )

    // Add dependencies for all upstream stages
    upstreamIds.foreach { upstreamId =>
      addDependency(dependencies, shuffleStageId, upstreamId)
    }

    shuffleStageId
  }

  // --- Metadata helpers ---

  /**
   * How a narrow operation changes partitioning metadata.
   *
   * Filter and the pair-key ops keep range and ordering: they do not replace the element or
   * reorder the partition. `map`, `flatMap`, and `mapPartitions` drop both. `keys` and `values`
   * drop hash as well, because the output is no longer a pair. A bypassed `repartition` is an
   * identity, so it keeps the upstream description. True shuffle stages set theirs in
   * `createShuffleStageUnified`. A new [[Operation]] subtype has to be handled here.
   */
  private def updatePartitioning(
      prev: Option[PartitioningInfo],
      op: Operation[Any, Any],
  ): Option[PartitioningInfo] = {
    val result = op match {
      case _: KeysOp[_, _] | _: ValuesOp[_, _] =>
        prev.map(_.withoutPairDistribution)

      case _: MapOp[_, _] | _: FlatMapOp[_, _] | _: MapPartitionsOp[_, _] =>
        prev.map(_.withoutRangeOrOrdering)

      case pbl: PartitionByLocalOp[_, _] =>
        Some(PartitioningInfo.hash(pbl.numPartitions))

      case rep: RepartitionOp[_] =>
        prev match {
          case Some(info) if info.numPartitions == rep.numPartitions => Some(info)
          case _ => Some(PartitioningInfo.unknown(rep.numPartitions))
        }

      case coal: CoalesceOp[_] =>
        Some(PartitioningInfo.unknown(coal.numPartitions))

      case _: FilterOp[_] | _: MapValuesOp[_, _, _] | _: FilterKeysOp[_, _] |
          _: FilterValuesOp[_, _] | _: FlatMapValuesOp[_, _, _] | _: DistinctOp[_] |
          _: GroupByKeyLocalOp[_, _] | _: ReduceByKeyLocalOp[_, _] =>
        prev
    }

    result.foreach { partitioning =>
      require(
        partitioning.numPartitions > 0,
        s"Invalid partitioning from operation $op: numPartitions must be > 0, got ${partitioning.numPartitions}",
      )
      partitioning.invalidReason.foreach { reason =>
        throw new IllegalArgumentException(
          s"Invalid partitioning from operation $op: $reason",
        )
      }
    }

    result
  }
