import logging
from collections import deque

import torch
import torch.fx as fx

from ... import ops  # noqa: F401
from ..pass_base import TensorCastGraphModulePass
from ..topo_sort import stable_topo_sort

logger = logging.getLogger(__name__)


class DispatchFFNCombinePass(TensorCastGraphModulePass):
    _QUANT_FULL_ARG_NAMES = (
        "x",
        "w",
        "w_scale",
        "w_offset",
        "x_scale",
        "x_offset",
        "bias",
        "out_dtype",
    )
    _QUANT_WEIGHT_ARG_NAMES = ("w", "w_scale", "w_offset", "bias", "out_dtype")
    _QUANT_WEIGHT_ARG_INDICES = (1, 2, 3, 6, 7)

    _GROUPED_MATMUL_OPS = {
        torch.ops.tensor_cast.grouped_matmul.default,
        torch.ops.tensor_cast.grouped_matmul_quant.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4.default,
        torch.ops.tensor_cast.grouped_matmul_fp8.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4.default,
    }

    _GROUPED_MATMUL_SWIGLU_OPS = {
        torch.ops.tensor_cast.grouped_matmul_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_fp8_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4_swiglu.default,
    }

    _GROUPED_MATMUL_M3_SWIGLU_OPS = {
        torch.ops.tensor_cast.grouped_matmul_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_fp8_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4_m3_swiglu.default,
    }

    _LINEAR_FFN_OPS = {
        torch.ops.tensor_cast.static_quant_linear.default,
        torch.ops.tensor_cast.static_quant_linear_int4.default,
        torch.ops.tensor_cast.fp8_linear.default,
        torch.ops.tensor_cast.mxfp4_linear.default,
    }

    _DFC_QUANT_WEIGHT_ONLY_OPS = {
        torch.ops.tensor_cast.grouped_matmul_quant.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4.default,
        torch.ops.tensor_cast.grouped_matmul_quant_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_swiglu.default,
        torch.ops.tensor_cast.static_quant_linear.default,
        torch.ops.tensor_cast.static_quant_linear_int4.default,
    }

    _SWIGLU_OPS = {
        torch.ops.tensor_cast.swiglu.default,
        torch.ops.tensor_cast.m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_fp8_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_fp8_m3_swiglu.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4_m3_swiglu.default,
    }

    _DFC_OP_MAP_GMM = {
        torch.ops.tensor_cast.grouped_matmul_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine.default,
        torch.ops.tensor_cast.grouped_matmul_quant_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant_int4.default,
        torch.ops.tensor_cast.grouped_matmul_fp8_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_fp8.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_mxfp4.default,
    }

    _DFC_OP_MAP_M3_GMM = {
        torch.ops.tensor_cast.grouped_matmul_m3_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_m3.default,
        torch.ops.tensor_cast.grouped_matmul_quant_m3_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant_m3.default,
        torch.ops.tensor_cast.grouped_matmul_quant_int4_m3_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant_int4_m3.default,
        torch.ops.tensor_cast.grouped_matmul_fp8_m3_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_fp8_m3.default,
        torch.ops.tensor_cast.grouped_matmul_mxfp4_m3_swiglu.default: torch.ops.tensor_cast.dispatch_ffn_combine_mxfp4_m3.default,
    }

    _DFC_OP_MAP_LINEAR = {
        torch.ops.tensor_cast.static_quant_linear.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant.default,
        torch.ops.tensor_cast.static_quant_linear_int4.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant_int4.default,
        torch.ops.tensor_cast.fp8_linear.default: torch.ops.tensor_cast.dispatch_ffn_combine_fp8.default,
        torch.ops.tensor_cast.mxfp4_linear.default: torch.ops.tensor_cast.dispatch_ffn_combine_mxfp4.default,
    }

    _DFC_OP_MAP_M3_LINEAR = {
        torch.ops.tensor_cast.static_quant_linear.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant_m3.default,
        torch.ops.tensor_cast.static_quant_linear_int4.default: torch.ops.tensor_cast.dispatch_ffn_combine_quant_int4_m3.default,
        torch.ops.tensor_cast.fp8_linear.default: torch.ops.tensor_cast.dispatch_ffn_combine_fp8_m3.default,
        torch.ops.tensor_cast.mxfp4_linear.default: torch.ops.tensor_cast.dispatch_ffn_combine_mxfp4_m3.default,
    }

    _MAX_TRAVERSE_DEPTH = 600

    def __call__(self, gm: fx.GraphModule) -> fx.GraphModule:
        graph = gm.graph
        modified = False

        all_permute_starts = []
        all_unpermute_ends = []

        for node in graph.nodes:
            if self._is_permute_token(node):
                all_permute_starts.append(node)
            if self._is_unpermute_token(node):
                all_unpermute_ends.append(node)

        processed_nodes = set()
        for start_node in all_permute_starts:
            if start_node in processed_nodes:
                continue

            region_nodes, end_node = self._collect_region_nodes_forward(
                start_node, processed_nodes, self._MAX_TRAVERSE_DEPTH
            )

            if not region_nodes or end_node is None:
                continue

            has_required_ops, reason = self._check_region_features(region_nodes)
            if not has_required_ops:
                logger.debug(
                    "DispatchFFNCombinePass skip region start=%s end=%s reason=%s",
                    start_node.name,
                    end_node.name,
                    reason,
                )
                continue

            result = self._resolve_dfc_variant(region_nodes)
            if result is None:
                logger.debug(
                    "DispatchFFNCombinePass skip: cannot resolve DFC variant (start=%s end=%s)",
                    start_node.name,
                    end_node.name,
                )
                continue

            dfc_target, gmm1_w_args, gmm2_w_args, rank_node, rank_group_node, extra_args = result

            fused_args = (
                start_node.args[0],
                start_node.args[1],
                *gmm1_w_args,
                *gmm2_w_args,
                *extra_args,
                rank_node,
                rank_group_node,
            )

            with graph.inserting_before(end_node):
                fused_node = graph.create_node(
                    "call_function",
                    dfc_target,
                    args=fused_args,
                    kwargs={},
                    name="dispatch_ffn_combine_fused",
                )

            end_node.replace_all_uses_with(fused_node)
            processed_nodes.update(region_nodes)
            modified = True

        if modified:
            stable_topo_sort(gm)
            gm.graph.eliminate_dead_code()
            gm.graph.lint()
            gm.recompile()

        return gm

    def _resolve_dfc_variant(self, region_nodes):
        all_to_all_node = None
        for node in region_nodes:
            if self._is_all_to_all(node):
                all_to_all_node = node
                break

        if all_to_all_node is not None:
            rank_node = all_to_all_node.args[3]
            rank_group_node = all_to_all_node.args[4]
        else:
            rank_node = 0
            rank_group_node = [0]

        # Detect if region contains M3 swiglu ops
        is_m3 = any(
            node.op == "call_function" and node.target in self._GROUPED_MATMUL_M3_SWIGLU_OPS
            for node in region_nodes
        ) or any(
            node.op == "call_function" and node.target == torch.ops.tensor_cast.m3_swiglu.default
            for node in region_nodes
        )

        # Case 1: Grouped ops (after SinkSplit + GroupedMatmulSwigluPass)
        gmm_swiglu_node = None
        gmm_plain_node = None
        for node in region_nodes:
            if self._is_grouped_matmul_swiglu(node) or self._is_grouped_matmul_m3_swiglu(node):
                gmm_swiglu_node = node
            elif self._is_grouped_matmul(node):
                gmm_plain_node = node

        if gmm_swiglu_node is not None and gmm_plain_node is not None:
            if is_m3:
                dfc_target = self._DFC_OP_MAP_M3_GMM.get(gmm_swiglu_node.target)
            else:
                dfc_target = self._DFC_OP_MAP_GMM.get(gmm_swiglu_node.target)
            if dfc_target is None:
                return None

            extra_args = ()
            if is_m3 and len(gmm_swiglu_node.args) >= 3:
                # grouped_matmul_*_m3_swiglu has extra alpha, limit args at the end
                # args signature: (x_list, w_list, bias_list, ..., alpha, limit)
                alpha = gmm_swiglu_node.args[-2]
                limit = gmm_swiglu_node.args[-1]
                extra_args = (alpha, limit)

            return (
                dfc_target,
                self._extract_grouped_gmm_args(gmm_swiglu_node, is_m3),
                self._extract_grouped_gmm_args(gmm_plain_node, False),
                rank_node,
                rank_group_node,
                extra_args,
            )

        if gmm_swiglu_node is not None and gmm_plain_node is None:
            logger.debug(
                "DFC: half-match — grouped_matmul_swiglu found but no "
                "grouped_matmul for down_proj. Skipping."
            )
            return None

        # Case 2: Unfused linear ops
        swiglu_nodes = []
        linear_nodes = []
        for node in region_nodes:
            if node.op == "call_function" and node.target in (
                torch.ops.tensor_cast.swiglu.default,
                torch.ops.tensor_cast.m3_swiglu.default,
            ):
                swiglu_nodes.append(node)
            if self._is_linear_ffn(node):
                linear_nodes.append(node)

        if not swiglu_nodes or not linear_nodes:
            logger.debug("DFC: no swiglu or linear_ffn nodes in region")
            return None

        linear_target = linear_nodes[0].target
        if is_m3:
            dfc_target = self._DFC_OP_MAP_M3_LINEAR.get(linear_target)
        else:
            dfc_target = self._DFC_OP_MAP_LINEAR.get(linear_target)
        if dfc_target is None:
            logger.debug("DFC: unmapped linear target=%s", linear_target)
            return None

        graph_order = {node: idx for idx, node in enumerate(linear_nodes[0].graph.nodes)}
        swiglu_nodes.sort(key=graph_order.get)

        gate_up_seen = set()
        gate_up_linears = []
        for swiglu_node in swiglu_nodes:
            for gate_up_node in self._collect_linear_predecessors(swiglu_node):
                if gate_up_node not in gate_up_seen:
                    gate_up_seen.add(gate_up_node)
                    gate_up_linears.append(gate_up_node)

        down_linears = [n for n in linear_nodes if n not in gate_up_seen]

        if not gate_up_linears:
            logger.debug("DFC: could not identify gate_up linear")
            return None

        if not down_linears:
            logger.debug("DFC: could not identify down_proj linear, skipping fusion")
            return None

        gate_up_linears.sort(key=graph_order.get)
        down_linears.sort(key=graph_order.get)

        gmm1_w_args = self._collect_linear_args_as_lists(gate_up_linears)
        gmm2_w_args = self._collect_linear_args_as_lists(down_linears)

        extra_args = ()
        if is_m3 and swiglu_nodes:
            first_swiglu = swiglu_nodes[0]
            if first_swiglu.target == torch.ops.tensor_cast.m3_swiglu.default and len(first_swiglu.args) >= 4:
                alpha = first_swiglu.args[2]
                limit = first_swiglu.args[3]
                extra_args = (alpha, limit)

        return (dfc_target, gmm1_w_args, gmm2_w_args, rank_node, rank_group_node, extra_args)

    @staticmethod
    def _collect_linear_args_as_lists(linear_nodes: list) -> tuple:
        if not linear_nodes:
            return ()
        template = linear_nodes[0]
        arg_indices = DispatchFFNCombinePass._get_linear_arg_indices_for_dfc(template.target)
        result = []
        for i in arg_indices:
            DispatchFFNCombinePass._check_node_arg_index(template, i)
            first_val = template.args[i]
            if isinstance(first_val, fx.Node) or first_val is None:
                for node in linear_nodes:
                    DispatchFFNCombinePass._check_node_arg_index(node, i)
                result.append([node.args[i] for node in linear_nodes])
            else:
                result.append(first_val)
        return tuple(result)

    def _collect_linear_predecessors(self, node: fx.Node) -> list[fx.Node]:
        predecessors = []
        seen = set()
        queue = [arg for arg in node.args if isinstance(arg, fx.Node)]

        while queue:
            current = queue.pop()
            if current in seen:
                continue
            seen.add(current)

            if self._is_linear_ffn(current):
                predecessors.append(current)
                continue

            for arg in getattr(current, "args", ()):
                if isinstance(arg, fx.Node):
                    queue.append(arg)

        return predecessors

    def _extract_grouped_gmm_args(self, node: fx.Node, is_m3: bool) -> tuple:
        arg_indices = self._get_weight_only_arg_indices(node.target)
        if arg_indices is not None:
            for i in arg_indices:
                self._check_node_arg_index(node, i)
            return tuple(node.args[i] for i in arg_indices)
        # For non-quant ops and M3, skip activation (args[0]) and trailing alpha/limit
        if is_m3:
            return node.args[1:-2]
        return node.args[1:]

    @classmethod
    def _get_weight_only_arg_indices(cls, target) -> tuple[int, ...] | None:
        if target in cls._DFC_QUANT_WEIGHT_ONLY_OPS:
            schema_arg_names = cls._get_schema_arg_names(target)
            if schema_arg_names != cls._QUANT_FULL_ARG_NAMES:
                raise ValueError(
                    "Unexpected DFC quant op schema for "
                    f"{target}: expected {cls._QUANT_FULL_ARG_NAMES}, "
                    f"got {schema_arg_names}"
                )
            return tuple(schema_arg_names.index(name) for name in cls._QUANT_WEIGHT_ARG_NAMES)
        return None

    @staticmethod
    def _get_linear_arg_indices_for_dfc(target) -> tuple[int, ...]:
        arg_indices = DispatchFFNCombinePass._get_weight_only_arg_indices(target)
        if arg_indices is not None:
            return arg_indices
        schema_arg_names = DispatchFFNCombinePass._get_schema_arg_names(target)
        return tuple(range(1, len(schema_arg_names)))

    @staticmethod
    def _get_schema_arg_names(target) -> tuple[str, ...]:
        schema = getattr(target, "_schema", None)
        if schema is None:
            raise TypeError(f"DFC argument extraction expects a torch op overload with a _schema, got {target!r}")
        return tuple(arg.name for arg in schema.arguments)

    @staticmethod
    def _check_node_arg_index(node: fx.Node, index: int) -> None:
        if index >= len(node.args):
            raise ValueError(
                "Unexpected argument count for DFC node "
                f"{node.name} ({node.target}): need index {index}, "
                f"but only {len(node.args)} args are present"
            )

    def _collect_region_nodes_forward(self, start_node: fx.Node, processed: set, max_depth: int) -> tuple[set, fx.Node]:
        region = set()
        q = deque([(start_node, 0)])
        end_node = None

        while q and end_node is None:
            n, depth = q.popleft()

            if depth > max_depth or n in region or n in processed:
                continue

            region.add(n)

            if self._is_unpermute_token(n):
                end_node = n
                continue

            if n.op in ["placeholder", "get_attr"]:
                continue

            for user in n.users:
                if isinstance(user, fx.Node) and user not in region:
                    q.append((user, depth + 1))

        return (region, end_node) if end_node else (set(), None)

    def _is_permute_token(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target == torch.ops.tensor_cast.init_routing_v2.default

    def _is_unpermute_token(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target == torch.ops.tensor_cast.unpermute_tokens.default

    def _is_grouped_matmul(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target in self._GROUPED_MATMUL_OPS

    def _is_grouped_matmul_swiglu(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target in self._GROUPED_MATMUL_SWIGLU_OPS

    def _is_grouped_matmul_m3_swiglu(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target in self._GROUPED_MATMUL_M3_SWIGLU_OPS

    def _is_linear_ffn(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target in self._LINEAR_FFN_OPS

    def _is_swiglu(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target in self._SWIGLU_OPS

    def _is_all_to_all(self, node: fx.Node) -> bool:
        return node.op == "call_function" and node.target == torch.ops.tensor_cast.all_to_all.default

    def _check_region_features(self, region: set) -> tuple[bool, str]:
        has_ffn_compute = False
        has_permute = False
        has_unpermute = False
        has_swiglu = False

        for node in region:
            if self._is_permute_token(node):
                has_permute = True
            if self._is_unpermute_token(node):
                has_unpermute = True
            if self._is_grouped_matmul(node) or self._is_grouped_matmul_swiglu(node) or self._is_grouped_matmul_m3_swiglu(node) or self._is_linear_ffn(node):
                has_ffn_compute = True
            if self._is_swiglu(node):
                has_swiglu = True

        if not has_permute:
            return False, "missing_init_routing_v2"
        if not has_unpermute:
            return False, "missing_unpermute_tokens"
        if not has_ffn_compute:
            return False, "missing_ffn_compute_ops"
        if not has_swiglu:
            return False, "missing_swiglu"
        return True, "matched"
