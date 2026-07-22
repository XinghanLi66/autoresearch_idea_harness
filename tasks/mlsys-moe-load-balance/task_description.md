# MoE Expert Parallelism Load Balancing

## Research Question

Design an efficient expert placement algorithm for Mixture-of-Experts (MoE) inference that assigns expert replicas to GPUs to minimize load imbalance — at both the GPU and node level — while preserving inter-node locality of replicas and keeping the rebalancing algorithm runtime low.

## Background

In MoE models (e.g., DeepSeek-V2/V3, Qwen3-MoE), different experts receive different amounts of traffic depending on the input distribution. During inference, experts are distributed across GPUs, and load imbalance causes some GPUs to become bottlenecks. The Expert Parallelism Load Balancer (EPLB) runs periodically to rebalance expert placement as workload patterns change.

The standard three-stage hierarchical algorithm is:
1. **Group-to-node packing**: Distribute expert groups across server nodes to balance inter-node load.
2. **Expert replication**: Create additional replicas of popular (hot) experts within each node.
3. **Replica-to-GPU packing**: Assign physical expert replicas to GPUs within each node.

The baseline greedy bin-packing approach uses Python for-loops to find optimal assignments, which is correct but slow (~100–250ms across configs). Vectorized tensor operations can achieve equivalent balance quality with orders of magnitude faster runtime, provided they preserve the node hierarchy.

## Task

Modify the editable section of `custom_eplb.py` to implement an expert placement algorithm. You must implement:
- `balanced_packing(weight, num_packs)` — pack weighted items into balanced packs
- `replicate_experts(weight, num_phy)` — decide expert replication counts and assign physical IDs
- `rebalance_experts(weight, num_replicas, num_groups, num_nodes, num_gpus)` — main entry point combining all three stages

## Interface

```python
def rebalance_experts(weight, num_replicas, num_groups, num_nodes, num_gpus):
    """
    Args:
        weight: [L, E] tensor — token load per expert per layer
        num_replicas: total physical expert slots (multiple of num_gpus)
        num_groups: number of expert groups (divisor of E)
        num_nodes: number of server nodes
        num_gpus: total GPUs (multiple of num_nodes)

    Returns:
        phy2log: [L, num_replicas] — logical expert ID for each physical slot
        log2phy: [L, E, max_rep] — physical IDs per expert (-1 = unused)
        logcnt: [L, E] — number of physical replicas per logical expert
    """
```

Constraints:
- `E % num_groups == 0`, `num_groups % num_nodes == 0`
- `num_gpus % num_nodes == 0`, `num_replicas % num_gpus == 0`
- Each GPU must receive exactly `num_replicas // num_gpus` physical experts
- Every logical expert must have at least one replica
- `logcnt.sum(-1)` must equal `num_replicas` for every layer

## Evaluation

Four MoE deployments. The first three are real-world architectures and visible during intermediate testing. The fourth (`stress-skew`) is **hidden** and only revealed in the final test, so the algorithm must generalize.

| Config | E (experts) | G (groups) | N (nodes) | D (GPUs) | R (replicas) | zipf · skew | Hidden |
|---|---|---|---|---|---|---|---|
| `deepseek-v3`  | 256 | 8  | 8  | 64  | 320 | 0.7 · 0.85 | no |
| `qwen3-moe`    | 128 | 8  | 4  | 32  | 160 | 0.5 · 0.70 | no |
| `deepseek-v2`  | 160 | 8  | 4  | 32  | 192 | 0.6 · 0.75 | no |
| `stress-skew`  | 256 | 32 | 16 | 128 | 384 | 1.0 · 0.95 | **yes** |

`stress-skew` is a synthetic stress test: 16-node hierarchy is the largest in the suite, the replication budget is tighter (1.5× rather than 2×), `groups_per_node = 2` makes Stage 1 group-to-node packing non-trivial, and the workload follows a long-tail Zipf distribution.

Per configuration, four metrics are reported:
- `balance` — `mean_gpu_load / max_gpu_load`, averaged over layers and trials. Higher is better, capped at 1.0 (perfect per-GPU balance).
- `balance_node` — `mean_node_load / max_node_load`, the same ratio at node granularity. Higher is better, capped at 1.0.
- `locality` — traffic-weighted node locality of replicas. For each (layer, expert) pair the harness counts how many distinct nodes hold a replica; the score is `1 / nodes_per_expert` averaged over experts (weighted by per-layer expert traffic) and over layers. A hierarchical scheme that keeps every expert's replicas on a single node scores 1.0; a flat scheme that scatters replicas across all nodes uniformly scores `1 / num_nodes`. This metric directly captures the inter-node communication cost that pure load-balance metrics ignore.
- `runtime_ms` — median wall time of the placement algorithm over 20 timed iterations, averaged across 10 workload trials. Lower is better.

The combined per-config score weights all four terms equally; the task score is the geometric mean across the four configs. **All three balance/locality metrics are required.** A flat scheme that scatters replicas to maximize per-GPU balance will lose `locality`; a method that co-locates replicas without addressing skew will lose `balance`. A strong submission must respect the node hierarchy, balance load at both levels, and stay fast.
