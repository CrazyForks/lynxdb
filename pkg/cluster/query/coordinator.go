package query

import (
	"context"
	"errors"
	"fmt"
	"io"
	"log/slog"
	"sync"
	"time"

	"github.com/vmihailenco/msgpack/v5"
	"go.opentelemetry.io/otel/attribute"
	"go.opentelemetry.io/otel/codes"
	"go.opentelemetry.io/otel/trace"
	"golang.org/x/sync/errgroup"

	"github.com/lynxbase/lynxdb/pkg/cluster/rpc"
	clusterpb "github.com/lynxbase/lynxdb/pkg/cluster/rpc/proto"
	"github.com/lynxbase/lynxdb/pkg/cluster/tracing"
	"github.com/lynxbase/lynxdb/pkg/engine/pipeline"
	"github.com/lynxbase/lynxdb/pkg/event"
	"github.com/lynxbase/lynxdb/pkg/logical"
	"github.com/lynxbase/lynxdb/pkg/logical/physical"
	"github.com/lynxbase/lynxdb/pkg/model"
)

// DefaultPartialFailureThreshold is the minimum fraction of successful shards
// before the query is considered a total failure. Below this, we return an error.
const DefaultPartialFailureThreshold = 0.5

// DistributedQueryResult holds the output of a scatter-gather query.
type DistributedQueryResult struct {
	Rows    []map[string]event.Value
	Meta    QueryMeta
	ScanMS  float64
	MergeMS float64
}

// QueryMeta holds metadata about shard-level execution for observability.
type QueryMeta struct {
	ShardsTotal    int      `json:"shards_total"`
	ShardsSuccess  int      `json:"shards_success"`
	ShardsFailed   int      `json:"shards_failed"`
	ShardsTimedOut int      `json:"shards_timed_out"`
	Partial        bool     `json:"partial"`
	Warnings       []string `json:"warnings,omitempty"`
}

// CoordinatorConfig holds settings for the distributed query coordinator.
type CoordinatorConfig struct {
	ShardQueryTimeout       time.Duration
	PartialResultsEnabled   bool
	PartialFailureThreshold float64
}

// Coordinator orchestrates scatter-gather query execution across the cluster.
// It plans the distributed query, prunes irrelevant shards, fans out to shard
// nodes via gRPC, and merges results using the appropriate strategy.
type Coordinator struct {
	clientPool *rpc.ClientPool
	pruner     *ShardPruner
	flowCtrl   *FlowController
	cfg        CoordinatorConfig
	logger     *slog.Logger
}

// NewCoordinator creates a new distributed query coordinator.
func NewCoordinator(
	clientPool *rpc.ClientPool,
	pruner *ShardPruner,
	flowCtrl *FlowController,
	cfg CoordinatorConfig,
	logger *slog.Logger,
) *Coordinator {
	if cfg.ShardQueryTimeout == 0 {
		cfg.ShardQueryTimeout = 30 * time.Second
	}
	if cfg.PartialFailureThreshold == 0 {
		cfg.PartialFailureThreshold = DefaultPartialFailureThreshold
	}

	return &Coordinator{
		clientPool: clientPool,
		pruner:     pruner,
		flowCtrl:   flowCtrl,
		cfg:        cfg,
		logger:     logger,
	}
}

// ExecuteQuery plans, fans out, and merges a distributed query using the
// logical IR plan. It delegates to ExecuteQueryIR. This is the sole entry
// point for distributed query execution after the SPL2 path was removed.
func (c *Coordinator) ExecuteQuery(
	ctx context.Context,
	prog *logical.Plan,
	hints *model.QueryHints,
) (*DistributedQueryResult, error) {
	return c.ExecuteQueryIR(ctx, prog, hints)
}

// executePartialAgg fans out partial aggregation to all shards and merges.
func (c *Coordinator) executePartialAgg(
	ctx context.Context,
	plan *DistributedPlan,
	targets []ShardTarget,
	meta *QueryMeta,
) ([]map[string]event.Value, error) {
	// Encode partial agg spec for RPC.
	specBytes, err := msgpack.Marshal(plan.PartialAggSpec)
	if err != nil {
		return nil, fmt.Errorf("Coordinator.executePartialAgg: encode spec: %w", err)
	}

	var (
		mu       sync.Mutex
		partials = make([][]*pipeline.PartialAggGroup, 0, len(targets))
	)

	g, gctx := errgroup.WithContext(ctx)

	for _, target := range targets {
		target := target
		g.Go(func() error {
			if err := c.flowCtrl.Acquire(gctx); err != nil {
				return err
			}
			defer c.flowCtrl.Release()

			shardCtx, shardSpan := tracing.Tracer().Start(gctx, "lynxdb.query.shard",
				trace.WithAttributes(
					attribute.String(tracing.AttrShardID, target.ShardID.String()),
					attribute.String(tracing.AttrNodeID, target.NodeAddr),
				))
			shardCtx, cancel := context.WithTimeout(shardCtx, c.cfg.ShardQueryTimeout)
			defer cancel()

			groups, err := c.queryShardPartialAgg(shardCtx, target, plan, specBytes)
			mu.Lock()
			defer mu.Unlock()

			if err != nil {
				meta.ShardsFailed++
				if shardCtx.Err() != nil {
					meta.ShardsTimedOut++
				}
				meta.Warnings = append(meta.Warnings,
					fmt.Sprintf("shard %s failed: %v", target.ShardID, err))
				c.logger.Warn("shard query failed",
					"shard", target.ShardID,
					"node", target.NodeAddr,
					"error", err)

				shardSpan.RecordError(err)
				shardSpan.SetStatus(codes.Error, "shard query failed")
				shardSpan.End()

				return nil // don't abort — collect partial results
			}

			meta.ShardsSuccess++
			if groups != nil {
				partials = append(partials, groups)
			}

			shardSpan.End()

			return nil
		})
	}

	if err := g.Wait(); err != nil {
		return nil, fmt.Errorf("Coordinator.executePartialAgg: %w", err)
	}

	if err := c.checkPartialFailure(meta); err != nil {
		return nil, err
	}

	// Merge all partial results.
	if plan.Strategy == MergeTopK && plan.TopK > 0 {
		return pipeline.MergePartialAggsTopK(partials, plan.PartialAggSpec, plan.TopK, plan.TopKSortFields), nil
	}

	return pipeline.MergePartialAggs(partials, plan.PartialAggSpec), nil
}

// executeConcat fans out full scans to all shards and concatenates results.
func (c *Coordinator) executeConcat(
	ctx context.Context,
	plan *DistributedPlan,
	targets []ShardTarget,
	meta *QueryMeta,
) ([]map[string]event.Value, error) {
	var (
		mu      sync.Mutex
		allRows []map[string]event.Value
	)

	g, gctx := errgroup.WithContext(ctx)

	for _, target := range targets {
		target := target
		g.Go(func() error {
			if err := c.flowCtrl.Acquire(gctx); err != nil {
				return err
			}
			defer c.flowCtrl.Release()

			shardCtx, shardSpan := tracing.Tracer().Start(gctx, "lynxdb.query.shard",
				trace.WithAttributes(
					attribute.String(tracing.AttrShardID, target.ShardID.String()),
					attribute.String(tracing.AttrNodeID, target.NodeAddr),
				))
			shardCtx, cancel := context.WithTimeout(shardCtx, c.cfg.ShardQueryTimeout)
			defer cancel()

			rows, err := c.queryShardConcat(shardCtx, target, plan)
			mu.Lock()
			defer mu.Unlock()

			if err != nil {
				meta.ShardsFailed++
				if shardCtx.Err() != nil {
					meta.ShardsTimedOut++
				}
				meta.Warnings = append(meta.Warnings,
					fmt.Sprintf("shard %s failed: %v", target.ShardID, err))

				shardSpan.RecordError(err)
				shardSpan.SetStatus(codes.Error, "shard query failed")
				shardSpan.End()

				return nil
			}

			meta.ShardsSuccess++
			allRows = append(allRows, rows...)

			shardSpan.End()

			return nil
		})
	}

	if err := g.Wait(); err != nil {
		return nil, fmt.Errorf("Coordinator.executeConcat: %w", err)
	}

	if err := c.checkPartialFailure(meta); err != nil {
		return nil, err
	}

	return allRows, nil
}

// queryShardPartialAgg sends a partial aggregation query to a single shard.
func (c *Coordinator) queryShardPartialAgg(
	ctx context.Context,
	target ShardTarget,
	plan *DistributedPlan,
	specBytes []byte,
) ([]*pipeline.PartialAggGroup, error) {
	conn, err := c.clientPool.GetConn(ctx, target.NodeAddr)
	if err != nil {
		return nil, fmt.Errorf("connect to %s: %w", target.NodeAddr, err)
	}

	client := clusterpb.NewQueryServiceClient(conn)
	stream, err := client.ExecuteQuery(ctx, &clusterpb.ExecuteQueryRequest{
		Query:          plan.ShardQuery,
		ShardId:        target.ShardID.String(),
		PartialAggSpec: specBytes,
	})
	if err != nil {
		return nil, fmt.Errorf("ExecuteQuery RPC: %w", err)
	}

	var groups []*pipeline.PartialAggGroup
	for {
		msg, err := stream.Recv()
		if err != nil {
			if errors.Is(err, io.EOF) {
				break
			}
			if ctx.Err() != nil {
				return groups, ctx.Err()
			}

			slog.Warn("cluster: partial agg stream error (swallowed)", "error", err)
			break
		}

		if len(msg.Row) == 0 {
			continue
		}

		var group pipeline.PartialAggGroup
		if err := msgpack.Unmarshal(msg.Row, &group); err != nil {
			return nil, fmt.Errorf("decode partial group: %w", err)
		}
		groups = append(groups, &group)
	}

	return groups, nil
}

// queryShardConcat sends a full scan query to a single shard and collects rows.
func (c *Coordinator) queryShardConcat(
	ctx context.Context,
	target ShardTarget,
	plan *DistributedPlan,
) ([]map[string]event.Value, error) {
	conn, err := c.clientPool.GetConn(ctx, target.NodeAddr)
	if err != nil {
		return nil, fmt.Errorf("connect to %s: %w", target.NodeAddr, err)
	}

	client := clusterpb.NewQueryServiceClient(conn)
	stream, err := client.ExecuteQuery(ctx, &clusterpb.ExecuteQueryRequest{
		Query:   plan.ShardQuery,
		ShardId: target.ShardID.String(),
	})
	if err != nil {
		return nil, fmt.Errorf("ExecuteQuery RPC: %w", err)
	}

	var rows []map[string]event.Value
	for {
		msg, err := stream.Recv()
		if err != nil {
			if ctx.Err() != nil {
				return rows, ctx.Err()
			}

			break
		}

		if len(msg.Row) == 0 {
			continue
		}

		var row map[string]event.Value
		if err := msgpack.Unmarshal(msg.Row, &row); err != nil {
			return nil, fmt.Errorf("decode row: %w", err)
		}
		rows = append(rows, row)
	}

	return rows, nil
}

// checkPartialFailure returns an error if too many shards failed.
func (c *Coordinator) checkPartialFailure(meta *QueryMeta) error {
	if meta.ShardsTotal == 0 {
		return nil
	}

	successRate := float64(meta.ShardsSuccess) / float64(meta.ShardsTotal)
	if successRate < c.cfg.PartialFailureThreshold {
		return fmt.Errorf("Coordinator: too many shard failures (%d/%d succeeded, threshold %.0f%%)",
			meta.ShardsSuccess, meta.ShardsTotal, c.cfg.PartialFailureThreshold*100)
	}

	return nil
}

// applyCoordCommands runs coordinator-only pipeline commands on merged rows.
//
// It constructs a synthetic logical.Plan whose leaf is a Scan("_merged")
// with the coordNodes chained above it, then executes via physical.Build
// using a RowScanIterator as the Source hook. This ensures coordinator-side
// stages (sort, head, dedup, etc.) are properly applied after merge.
//
// CoordNodes are cloned bottom-up to avoid mutating the shared IR plan tree.
// The IR planner's split detaches coord nodes from the original tree, but
// their Input pointers may still reference shared nodes. We rebuild the
// chain with fresh unaryNode.Input wiring so the physical builder sees a
// clean single-child chain from root down to the synthetic Scan.
func applyCoordCommands(ctx context.Context, rows []map[string]event.Value, coordNodes []logical.Node) ([]map[string]event.Value, error) {
	if len(coordNodes) == 0 {
		return rows, nil
	}

	// Build a synthetic plan: Scan("_merged") -> coordNodes[0] -> ... -> coordNodes[N-1]
	// The coordNodes are in pipeline order (first = closest to scan).
	//
	// Clone each node to avoid mutating the shared IR tree. We use
	// SetChildren to rewire the chain bottom-up.
	syntheticScan := &logical.Scan{
		Sources: []logical.SourcePattern{
			{Kind: 0, Name: "_merged"},
		},
	}

	// Clone coord nodes and rebuild the chain.
	cloned := make([]logical.Node, len(coordNodes))
	for i, n := range coordNodes {
		cloned[i] = cloneCoordNode(n)
	}

	// Wire: cloned[0].Input = syntheticScan, cloned[1].Input = cloned[0], etc.
	cloned[0].SetChildren([]logical.Node{syntheticScan})
	for i := 1; i < len(cloned); i++ {
		cloned[i].SetChildren([]logical.Node{cloned[i-1]})
	}

	plan := &logical.Plan{
		Root: cloned[len(cloned)-1],
	}

	// Build the physical pipeline with a Source hook that returns the merged rows.
	// Pass the caller's context so CTE materialization and pipeline execution
	// honour cancellation and deadlines.
	iter, err := physical.Build(plan, physical.BuildOptions{
		Source: func(_ *logical.Scan) (pipeline.Iterator, error) {
			return pipeline.NewRowScanIterator(rows, pipeline.DefaultBatchSize), nil
		},
		Now:     time.Now(),
		Context: ctx,
	})
	if err != nil {
		return nil, fmt.Errorf("applyCoordCommands: physical.Build: %w", err)
	}

	result, err := pipeline.CollectAll(ctx, iter)
	if err != nil {
		return nil, fmt.Errorf("applyCoordCommands: collect: %w", err)
	}

	return result, nil
}

// cloneCoordNode creates a shallow copy of a logical node so that SetChildren
// does not mutate the original IR plan tree. Only the node shell is copied;
// the expression/config fields are shared (they are read-only during execution).
func cloneCoordNode(n logical.Node) logical.Node {
	switch nd := n.(type) {
	case *logical.Sort:
		clone := *nd
		return &clone
	case *logical.Limit:
		clone := *nd
		return &clone
	case *logical.Dedup:
		clone := *nd
		return &clone
	case *logical.TopK:
		clone := *nd
		return &clone
	case *logical.Filter:
		clone := *nd
		return &clone
	case *logical.Extend:
		clone := *nd
		return &clone
	case *logical.Project:
		clone := *nd
		return &clone
	case *logical.Aggregate:
		clone := *nd
		return &clone
	case *logical.Join:
		clone := *nd
		return &clone
	case *logical.Describe:
		clone := *nd
		return &clone
	case *logical.Helper:
		clone := *nd
		return &clone
	default:
		// Unknown node type: return as-is (caller should not pass Scan here).
		return n
	}
}
