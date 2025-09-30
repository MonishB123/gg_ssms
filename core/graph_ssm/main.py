from torch.autograd import Function
from torch.autograd.function import once_differentiable
from tree_scan_lan import _C
import torch
import torch.nn as nn
from einops import rearrange, repeat
import math
from .tree_utils import prune_tree_by_weight


class _MST(Function):
    @staticmethod
    def forward(ctx, edge_index, edge_weight, vertex_index):
        edge_out = _C.mst_forward(edge_index, edge_weight, vertex_index)
        return edge_out

    @staticmethod
    @once_differentiable
    def backward(ctx, grad_output):
        return None, None, None


class _BFS(Function):
    @staticmethod
    def forward(ctx, edge_index, max_adj_per_vertex):
        sorted_index, sorted_parent, sorted_child, _ = _C.bfs_forward(
            edge_index, max_adj_per_vertex
        )
        return sorted_index, sorted_parent, sorted_child


class _Refine(Function):
    @staticmethod
    def forward(
        ctx, feature_in, edge_weight, sorted_index, sorted_parent, sorted_child
    ):
        feature_out = _C.tree_scan_refine_forward(
            feature_in, edge_weight, sorted_index, sorted_parent, sorted_child
        )

        ctx.save_for_backward(
            feature_out, edge_weight, sorted_index, sorted_parent, sorted_child
        )
        return feature_out

    @staticmethod
    @once_differentiable
    def backward(ctx, grad_output):
        feature_out, edge_weight, sorted_index, sorted_parent, sorted_child = (
            ctx.saved_tensors
        )

        grad_feature, grad_edge = _C.tree_scan_refine_backward_feature(
            feature_out,
            edge_weight,
            sorted_index,
            sorted_parent,
            sorted_child,
            grad_output,
        )
        return grad_feature, grad_edge, None, None, None


def norm2_distance(fm_ref, fm_tar):
    diff = fm_ref - fm_tar
    weight = (diff * diff).sum(dim=-2)
    return torch.exp(weight)  # with - is for max tree


def cosine_distance(fm_ref, fm_tar):
    print("\nDebug cosine_distance:")
    print("- fm_ref shape:", fm_ref.shape)
    print("- fm_tar shape:", fm_tar.shape)
    print("- fm_ref stats - mean:", fm_ref.mean().item(), "std:", fm_ref.std().item())
    print("- fm_tar stats - mean:", fm_tar.mean().item(), "std:", fm_tar.std().item())
    weight = -torch.cosine_similarity(fm_ref, fm_tar, dim=1)
    print("- cosine sim stats - mean:", weight.mean().item(), "std:", weight.std().item())
    print("- cosine sim contains NaN:", torch.isnan(weight).any().item())
    print("- cosine sim contains Inf:", torch.isinf(weight).any().item())
    result = torch.exp(weight)  # with - is for min tree
    print("- exp result stats - mean:", result.mean().item(), "std:", result.std().item())
    print("- exp result contains NaN:", torch.isnan(result).any().item())
    print("- exp result contains Inf:", torch.isinf(result).any().item())
    if torch.isnan(result).any() or torch.isinf(result).any():
        print("- First NaN/Inf positions:", torch.where(torch.isnan(result) | torch.isinf(result)))
    return result


def batch_index_opr(data, index, debug=False):
    with torch.no_grad():
        channel = data.shape[1]
        index = index.unsqueeze(1).expand(-1, channel, -1).long()
        
        if debug:
            print("\nDebug batch_index_opr:")
            print("- data shape:", data.shape)
            print("- index shape:", index.shape)
            
            # Force CUDA synchronization before accessing values
            try:
                torch.cuda.synchronize()
                idx_min = index.min().item()
                idx_max = index.max().item()
                print(f"- index min/max: {idx_min} {idx_max}")
            except Exception as e:
                print(f"- Error getting index min/max: {e}")
                
            try:
                torch.cuda.synchronize()
                data_mean = data.mean().item()
                data_std = data.std().item()
                print(f"- data stats - mean: {data_mean} std: {data_std}")
            except Exception as e:
                print(f"- Error getting data stats: {e}")
                
            print("- data contains NaN:", torch.isnan(data).any().item())
            print("- data contains Inf:", torch.isinf(data).any().item())
            if torch.isnan(data).any() or torch.isinf(data).any():
                print("- First NaN/Inf positions:", torch.where(torch.isnan(data) | torch.isinf(data)))
            
    torch.cuda.synchronize()  # Ensure gather completes
    data = torch.gather(data, 2, index)
    torch.cuda.synchronize()
    
    if debug:
        print("- output stats - mean:", data.mean().item(), "std:", data.std().item())
        print("- output contains NaN:", torch.isnan(data).any().item())
        print("- output contains Inf:", torch.isinf(data).any().item())
        if torch.isnan(data).any() or torch.isinf(data).any():
            print("- First NaN/Inf positions in output:", torch.where(torch.isnan(data) | torch.isinf(data)))
    return data


def tree_scanning_algorithm(self, input_states, context_len):
    batch_size, seq_len, _ = input_states.shape
    dtype = input_states.dtype
    device = input_states.device
    
    # Add a static counter to track iterations
    if not hasattr(tree_scanning_algorithm, 'iteration_count'):
        tree_scanning_algorithm.iteration_count = 0
    tree_scanning_algorithm.iteration_count += 1
    # 1. Gated MLP's linear projection
    projected_states = self.in_proj(input_states).transpose(
        1, 2
    )  # [batch, 2 * intermediate_size, seq_len]
    hidden_states, gate = projected_states.chunk(2, dim=1)

    hidden_states = self.act(
        self.conv1d(hidden_states)[..., :seq_len]
    )  # [batch, intermediate_size, seq_len]
    # 3. State Space Model sequence transformation
    # 3.a. Selection:  [batch, seq_len, self.time_step_rank + self.ssm_state_size * 2]
    ssm_parameters = self.x_proj(hidden_states.transpose(1, 2))
    time_step, B, C = torch.split(
        ssm_parameters,
        [self.dt_rank, self.d_state, self.d_state],
        dim=-1,
    )
    discrete_time_step = self.dt_proj(time_step)  # [batch, seq_len, intermediate_size]
    discrete_time_step = nn.functional.softplus(discrete_time_step).transpose(
        1, 2
    )  # [batch, intermediate_size, seq_len]
    # 3.b. Discretization: B and C to [batch, seq_len, intermediate_size, ssm_state_size] (SRAM)
    A = -torch.exp(self.A_log.float())  # [intermediate_size, ssm_state_size]
    discrete_A = torch.exp(
        A[None, :, None, :] * discrete_time_step[:, :, :, None]
    )  # [batch, intermediate_size, seq_len, ssm_state_size]
    discrete_B = (
        discrete_time_step[:, :, :, None] * B[:, None, :, :].float()
    )  # [batch, intermediade_size, seq_len, ssm_state_size]
    deltaB_u = discrete_B * hidden_states[:, :, :, None].float()
    ### tree scan
    weight = rearrange(discrete_A, "b d l n -> b (d n) l").contiguous()
    feature_in = rearrange(deltaB_u, "b d l n -> b (d n) l").contiguous()
    feature_in = torch.flip(feature_in, dims=[-1]).contiguous()
    weight = torch.roll(torch.flip(weight, dims=[-1]), 1, -1).contiguous()

    mst = _MST.apply
    bfs = _BFS.apply
    refine = _Refine.apply

    ### hand-build tree
    tree_ = []
    for i in range(seq_len - 1):
        tree_.append([i, i + 1])
    tree_ = torch.tensor(tree_, dtype=torch.int32).to(device)
    tree = tree_.repeat(batch_size, 1, 1)
    sorted_index1, sorted_parent1, sorted_child1 = bfs(tree, 4)

    ### build tree by feature
    try:
        context_len = min(context_len)
    except:
        context_len = context_len
    with torch.no_grad():

        def generate_pairs(L, prompt_len):
            pairs = []
            for i in range(0, L - prompt_len):
                pairs.append([i, i + 1])
            for i in range(L - prompt_len, L - 3):
                pairs.append([i, i + 1])
                pairs.append([i, i + 2])
                pairs.append([i, i + 3])
            pairs.append([L - 3, L - 2])
            pairs.append([L - 3, L - 1])
            pairs.append([L - 2, L - 1])
            return pairs

        if context_len > 2:
            pairs = torch.tensor(
                generate_pairs(seq_len, context_len),
                dtype=torch.int32,
                device=feature_in.device,
            )
            data1 = torch.index_select(feature_in, 2, pairs[:, 0])
            data2 = torch.index_select(feature_in, 2, pairs[:, 1])
            # import pdb;pdb.set_trace()
            tree_weight = cosine_distance(data1, data2)

            # Print the pairs and their weights before MST (only for first iteration)
            if tree_scanning_algorithm.iteration_count == 1:
                print("\nInput pairs to MST:")
                print(pairs)
                print("\nInput weights to MST:")
                print(tree_weight)

            # Returns the edges that from the MST
            # mst(edges, weight) -> edges_out
            # edges is [batch_size, num_edges, 2]
            # weight is [batch_size, num_edges]
            # edges_out is [batch_size, num_vertices - 1, 2]
            
            # Only enable debug/connectivity check on first iteration
            is_first_iter = (tree_scanning_algorithm.iteration_count == 1)
            
            print(f"\n[Iter {tree_scanning_algorithm.iteration_count}] About to call MST...")
            torch.cuda.synchronize()
            tree = mst(pairs.repeat(batch_size, 1, 1), tree_weight, seq_len)
            torch.cuda.synchronize()
            print(f"[Iter {tree_scanning_algorithm.iteration_count}] MST completed, tree shape: {tree.shape}")

            if is_first_iter:
                print("\nResulting MST edges:")
                print(tree.squeeze(0))
            
            # TEMPORARILY DISABLE PRUNING TO TEST IF IT'S CAUSING THE HANG
            # The duplicate-edge padding strategy might be creating invalid tree structures
            # that break the refine CUDA kernel on iteration 2
            
            # pruning_threshold = 0.45
            # 
            # print(f"[Iter {tree_scanning_algorithm.iteration_count}] About to prune (threshold={pruning_threshold})...")
            # torch.cuda.synchronize()
            # 
            # try:
            #     tree = prune_tree_by_weight(
            #         tree, pairs, tree_weight, pruning_threshold,
            #         debug=is_first_iter,
            #         check_connectivity=is_first_iter
            #     )
            #     torch.cuda.synchronize()
            #     print(f"[Iter {tree_scanning_algorithm.iteration_count}] Pruning completed, tree shape: {tree.shape}")
            # except Exception as e:
            #     print(f"[Iter {tree_scanning_algorithm.iteration_count}] Error during pruning: {str(e)}")
            #     raise
            # 
            # if is_first_iter:
            #     print(f"\nPruned tree (threshold={pruning_threshold}):")
            #     print(tree.squeeze(0))
            
            print(f"[Iter {tree_scanning_algorithm.iteration_count}] Pruning DISABLED for testing")
            
            if is_first_iter:
                print("\nStarting BFS operation...")
                print(f"Input tree shape to BFS: {tree.shape}")
                print(f"context_len: {context_len}")
            
            print(f"[Iter {tree_scanning_algorithm.iteration_count}] About to call BFS...")
            torch.cuda.synchronize()
            sorted_index2, sorted_parent2, sorted_child2 = bfs(tree, context_len)
            torch.cuda.synchronize()
            print(f"[Iter {tree_scanning_algorithm.iteration_count}] BFS completed")
            
            # Debug BFS output on iteration 2 to diagnose refine hang
            if tree_scanning_algorithm.iteration_count == 2:
                print(f"\n[DEBUG Iter 2] BFS output validation:")
                print(f"  sorted_index2 shape: {sorted_index2.shape}")
                try:
                    torch.cuda.synchronize()
                    idx2_min = sorted_index2.min().item()
                    idx2_max = sorted_index2.max().item()
                    print(f"  sorted_index2 range: [{idx2_min}, {idx2_max}]")
                    print(f"  sorted_parent2 range: [{sorted_parent2.min().item()}, {sorted_parent2.max().item()}]")
                    print(f"  sorted_child2 range: [{sorted_child2.min().item()}, {sorted_child2.max().item()}]")
                    print(f"  sorted_child2 shape: {sorted_child2.shape}")
                    # Check for issues
                    if idx2_min < 0 or idx2_max >= context_len:
                        print(f"  ERROR: Invalid sorted_index2 values!")
                except Exception as e:
                    print(f"  Error checking BFS output: {e}")
            
            if is_first_iter:
                print("BFS completed successfully")
                print(f"sorted_index2 shape: {sorted_index2.shape}")
                print(f"sorted_parent2 shape: {sorted_parent2.shape}")
                print(f"sorted_child2 shape: {sorted_child2.shape}")
                
                # Validate sorted_index2
                try:
                    torch.cuda.synchronize()
                    idx2_min = sorted_index2.min().item()
                    idx2_max = sorted_index2.max().item()
                    print(f"sorted_index2 range: [{idx2_min}, {idx2_max}]")
                    if idx2_min < 0 or idx2_max >= context_len:
                        print(f"WARNING: sorted_index2 has invalid indices! Expected [0, {context_len-1}], got [{idx2_min}, {idx2_max}]")
                except Exception as e:
                    print(f"Error validating sorted_index2: {e}")
        else:
            print("\nSkipping BFS, using sorted indices from first tree...")
            sorted_index2, sorted_parent2, sorted_child2 = (
                sorted_index1,
                sorted_parent1,
                sorted_child1,
            )
            print("Copied sorted indices successfully")

        # import pdb;pdb.set_trace()
    # import pdb;pdb.set_trace()
    # Only print debug info on first iteration
    if hasattr(tree_scanning_algorithm, 'iteration_count') and tree_scanning_algorithm.iteration_count == 1:
        print("\nStarting first refine operation...")
        print(f"feature_in shape: {feature_in.shape}")
        print(f"weight shape: {weight.shape}")
        print(f"sorted_index1 shape: {sorted_index1.shape}")
        print(f"sorted_parent1 shape: {sorted_parent1.shape}")
        print(f"sorted_child1 shape: {sorted_child1.shape}")
    
    print(f"[Iter {tree_scanning_algorithm.iteration_count}] About to call refine #1...")
    torch.cuda.synchronize()
    feature_out1 = refine(
        feature_in, weight, sorted_index1, sorted_parent1, sorted_child1
    )
    torch.cuda.synchronize()
    print(f"[Iter {tree_scanning_algorithm.iteration_count}] Refine #1 completed")
    
    if hasattr(tree_scanning_algorithm, 'iteration_count') and tree_scanning_algorithm.iteration_count == 1:
        print(f"feature_out1 shape after first refine: {feature_out1.shape}")
        print("\nStarting batch_index_opr...")
        print(f"weight shape before batch_index_opr: {weight.shape}")
        print(f"sorted_index2 shape: {sorted_index2.shape}")
    
    print(f"[Iter {tree_scanning_algorithm.iteration_count}] About to call batch_index_opr...")
    edge_weight = batch_index_opr(weight, sorted_index2, debug=(hasattr(tree_scanning_algorithm, 'iteration_count') and tree_scanning_algorithm.iteration_count == 1))
    print(f"[Iter {tree_scanning_algorithm.iteration_count}] batch_index_opr completed")
    
    if hasattr(tree_scanning_algorithm, 'iteration_count') and tree_scanning_algorithm.iteration_count == 1:
        print(f"edge_weight shape after batch_index_opr: {edge_weight.shape}")
        print("\nStarting second refine operation...")
        print(f"feature_in shape: {feature_in.shape}")
        print(f"edge_weight shape: {edge_weight.shape}")
        print(f"sorted_index2 shape: {sorted_index2.shape}")
        print(f"sorted_parent2 shape: {sorted_parent2.shape}")
        print(f"sorted_child2 shape: {sorted_child2.shape}")
    
    print(f"[Iter {tree_scanning_algorithm.iteration_count}] About to call refine #2...")
    torch.cuda.synchronize()
    feature_out2 = refine(
        feature_in, edge_weight, sorted_index2, sorted_parent2, sorted_child2
    )
    torch.cuda.synchronize()
    print(f"[Iter {tree_scanning_algorithm.iteration_count}] Refine #2 completed")
    
    if hasattr(tree_scanning_algorithm, 'iteration_count') and tree_scanning_algorithm.iteration_count == 1:
        print(f"feature_out2 shape after second refine: {feature_out2.shape}")
        print("\nCombining feature outputs...")
    
    feature_out = (
        feature_out2 * 0.3 + feature_out1
    )  # 0.3 is scaling factor (hyperparameter)
    
    if hasattr(tree_scanning_algorithm, 'iteration_count') and tree_scanning_algorithm.iteration_count == 1:
        print(f"Final feature_out shape: {feature_out.shape}")

    print("\nStarting final feature transformations...")
    print("1. Flipping and rearranging feature_out...")
    feature_out_flipped = torch.flip(feature_out.to(dtype), dims=[-1])
    print(f"- After flip shape: {feature_out_flipped.shape}")
    
    feature_out = rearrange(
        feature_out_flipped,
        "b (d n) l -> b l d n",
        b=batch_size,
        n=discrete_A.shape[-1],
    ).contiguous()
    print(f"- After rearrange shape: {feature_out.shape}")
    
    print("\n2. Computing scan output...")
    print(f"- feature_out shape: {feature_out.shape}")
    print(f"- C shape: {C.shape}")
    C_expanded = C.unsqueeze(-1)
    print(f"- C expanded shape: {C_expanded.shape}")
    
    scan_output_ = (
        (feature_out @ C_expanded).squeeze(-1).transpose(-1, -2)
    )  # (B, L, D, N) @ (B, L, N, 1) -> (B, L, D, 1)
    print(f"- scan_output_ shape: {scan_output_.shape}")

    print("\n3. Adding hidden states contribution...")
    print(f"- hidden_states shape: {hidden_states.shape}")
    print(f"- self.D shape: {self.D.shape}")
    hidden_contribution = hidden_states * self.D[None, :, None]
    print(f"- hidden contribution shape: {hidden_contribution.shape}")
    
    # [batch, seq_len, intermediade_size]
    scan_output = scan_output_ + hidden_contribution
    print(f"- scan_output after addition shape: {scan_output.shape}")
    
    print("\n4. Applying gate activation...")
    print(f"- gate shape: {gate.shape}")
    gate_activated = self.act(gate)
    print(f"- activated gate shape: {gate_activated.shape}")
    scan_output = scan_output * gate_activated
    print(f"- gated scan_output shape: {scan_output.shape}")
    
    print("\n5. Final projection...")
    scan_output_transposed = scan_output.transpose(1, 2)
    print(f"- transposed scan_output shape: {scan_output_transposed.shape}")
    # 4. Final linear projection
    contextualized_states = self.out_proj(
        scan_output_transposed
    )  # [batch, seq_len, hidden_size]
    print(f"- final contextualized_states shape: {contextualized_states.shape}")
    return contextualized_states


class GraphSSM(nn.Module):
    def __init__(
        self,
        d_model,
        d_state=16,
        d_conv=4,
        expand=2,
        dt_rank="auto",
        dt_min=0.001,
        dt_max=0.1,
        dt_init="random",
        dt_scale=1.0,
        dt_init_floor=1e-4,
        conv_bias=True,
        bias=False,
        use_fast_path=True,  # Fused kernel options
        layer_idx=None,
        device=None,
        dtype=None,
    ):
        factory_kwargs = {"device": device, "dtype": dtype}
        super().__init__()
        self.d_model = d_model
        self.d_state = d_state
        self.d_conv = d_conv
        self.expand = expand
        self.d_inner = int(self.expand * self.d_model)
        self.dt_rank = math.ceil(self.d_model / 16) if dt_rank == "auto" else dt_rank
        self.use_fast_path = use_fast_path
        self.layer_idx = layer_idx

        self.in_proj = nn.Linear(
            self.d_model, self.d_inner * 2, bias=bias, **factory_kwargs
        )

        self.conv1d = nn.Conv1d(
            in_channels=self.d_inner,
            out_channels=self.d_inner,
            bias=conv_bias,
            kernel_size=d_conv,
            groups=self.d_inner,
            padding=d_conv - 1,
            **factory_kwargs,
        )

        self.activation = "silu"
        self.act = nn.SiLU()

        self.x_proj = nn.Linear(
            self.d_inner, self.dt_rank + self.d_state * 2, bias=False, **factory_kwargs
        )
        self.dt_proj = nn.Linear(
            self.dt_rank, self.d_inner, bias=True, **factory_kwargs
        )

        # Initialize special dt projection to preserve variance at initialization
        dt_init_std = self.dt_rank**-0.5 * dt_scale
        if dt_init == "constant":
            nn.init.constant_(self.dt_proj.weight, dt_init_std)
        elif dt_init == "random":
            nn.init.uniform_(self.dt_proj.weight, -dt_init_std, dt_init_std)
        else:
            raise NotImplementedError

        # Initialize dt bias so that F.softplus(dt_bias) is between dt_min and dt_max
        dt = torch.exp(
            torch.rand(self.d_inner, **factory_kwargs)
            * (math.log(dt_max) - math.log(dt_min))
            + math.log(dt_min)
        ).clamp(min=dt_init_floor)
        # Inverse of softplus: https://github.com/pytorch/pytorch/issues/72759
        inv_dt = dt + torch.log(-torch.expm1(-dt))
        with torch.no_grad():
            self.dt_proj.bias.copy_(inv_dt)
        # Our initialization would set all Linear.bias to zero, need to mark this one as _no_reinit
        self.dt_proj.bias._no_reinit = True

        # S4D real initialization
        A = repeat(
            torch.arange(1, self.d_state + 1, dtype=torch.float32, device=device),
            "n -> d n",
            d=self.d_inner,
        ).contiguous()
        A_log = torch.log(A)  # Keep A_log in fp32
        self.A_log = nn.Parameter(A_log)
        self.A_log._no_weight_decay = True

        # D "skip" parameter
        self.D = nn.Parameter(torch.ones(self.d_inner, device=device))  # Keep in fp32
        self.D._no_weight_decay = True

        self.out_proj = nn.Linear(
            self.d_inner, self.d_model, bias=bias, **factory_kwargs
        )

    def forward(self, input_states, context_len):
        return tree_scanning_algorithm(self, input_states, context_len)


if __name__ == "__main__":
    # Example hyperparameters
    d_model = 16
    seq_len = 12
    batch_size = 1  # Set to 1 for clearer visualization
    context_len = 4  # Or pass in a list, e.g., [4, 4] for each sample

    print(f"\nRunning with parameters:")
    print(f"d_model: {d_model}")
    print(f"seq_len: {seq_len}")
    print(f"batch_size: {batch_size}")
    print(f"context_len: {context_len}")

    # Create random input tensor
    torch.manual_seed(42)  # For reproducibility
    x = torch.randn(batch_size, seq_len, d_model)

    # Instantiate the GraphSSM layer
    model = GraphSSM(d_model=d_model)

    # Forward pass
    print("\nRunning forward pass...")
    output = model(x, context_len)

    print("\nInput shape:", x.shape)  # (B, L, d_model)
    print("Output shape:", output.shape)  # (B, L, d_model)
    # Now 'output' contains the contextualized representation
