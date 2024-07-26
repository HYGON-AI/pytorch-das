import torch
import logging
import torch.fx as fx
from typing import Type, Dict, Any, Tuple, Iterable, Optional, List, cast
from torch.overrides import TorchFunctionMode
from torch.fx.experimental.optimization import (
    replace_node_module,
)
from torch.nn import functional as F
log = logging.getLogger(__name__)

import operator

class AutogradMonkeypatch(TorchFunctionMode):
    def __torch_function__(self, func, types, args=(), kwargs=None):
        if not kwargs:
            kwargs = {}
        return func(*args, **kwargs)

patch_functions = AutogradMonkeypatch

def fetch_attr(target: str, mod):
    target_atoms = target.split(".")
    attr_itr = mod
    for i, atom in enumerate(target_atoms):
        if not hasattr(attr_itr, atom):
            raise RuntimeError(
                f"Node referenced nonexistant target {'.'.join(target_atoms[:i])}"
            )
        attr_itr = getattr(attr_itr, atom)
    return attr_itr

def matches_two_module_two_function_pattern(pattern, node, modules):
    if len(node.args) == 0:
        return False
    # the second node is call_function or call_method
    if node.op != "call_module":
        return False
    if not isinstance(node.target, str):
        return False
    if type(modules[node.target]) is not pattern[3]:
        return False
    if node.target not in modules:
        return False
    if node.args[0].target is not pattern[2]:
        return False
    # make sure node.args[0] output is only used by current node.
    if len(node.args[0].users) > 1:
        return False
    if not isinstance(node.args[0], torch.fx.Node) or not isinstance(node, torch.fx.Node):
        return False
    # the first node is call_module
    if node.args[0].args[0].op != "call_module":
        return False
    if not isinstance(node.args[0].args[0].target, str):
        return False
    if node.args[0].args[0].target not in modules:
        return False
    if type(modules[node.args[0].args[0].target]) is not pattern[1]:
        return False
    if not isinstance(node.args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].users) > 1:
        return False
    if node.args[0].args[0].args[0].target is not pattern[0]:
        return False
    if len(node.args[0].args[0].args[0].users) > 1:
        return False
    return True

def matches_two_module_function_pattern(pattern, node, modules):
    if len(node.args) == 0:
        return False
    # the second node is call_function or call_method
    if node.op != "call_module":
        return False
    if not isinstance(node.target, str):
        return False
    if type(modules[node.target]) is not pattern[2]:
        return False
    if node.target not in modules:
        return False
    if node.args[0].target is not pattern[1]:
        return False
    # make sure node.args[0] output is only used by current node.
    if len(node.args[0].users) > 1:
        return False
    if not isinstance(node.args[0], torch.fx.Node) or not isinstance(node, torch.fx.Node):
        return False
    # the first node is call_module
    if node.args[0].args[0].op != "call_module":
        return False
    if not isinstance(node.args[0].args[0].target, str):
        return False
    if node.args[0].args[0].target not in modules:
        return False
    if type(modules[node.args[0].args[0].target]) is not pattern[0]:
        return False
    if not isinstance(node.args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].users) > 1:
        return False
    return True

def matches_module_two_function_pattern(pattern, node, modules):
    if len(node.args) == 0:
        return False
    if node.target is not pattern[2]:
        return False
    # the second node is call_function or call_method
    if node.args[0].op != "call_module":
        return False
    if not isinstance(node.args[0].target, str):
        return False
    if type(modules[node.args[0].target]) is not pattern[1]:
        return False
    if node.args[0].target not in modules:
        return False
    # make sure node.args[0] output is only used by current node.
    if len(node.args[0].users) > 1:
        return False
    if not isinstance(node.args[0], torch.fx.Node) or not isinstance(node, torch.fx.Node):
        return False
    if not isinstance(node.args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].users) > 1:
        return False
    if node.args[0].args[0].target is not pattern[0]:
        return False
    return True

# Works for length 1 patterns with 1 function/method.
def matches_module_function_pattern(pattern, node, modules):
    if len(node.args) == 0:
        return False
    if node.target is not pattern[1]:
        return False
    if node.op != "call_function" and node.op != "call_method":
        return False
    if node.args[0].op != "call_module":
        return False
    # make sure node.args[0] output is only used by current node.
    if len(node.args[0].users) > 1:
        return False
    if not isinstance(node.args[0].target, str):
        return False
    if type(modules[node.args[0].target]) is not pattern[0]:
        return False
    if node.args[0].target not in modules:
        return False
    if not isinstance(node.args[0], torch.fx.Node) or not isinstance(node, torch.fx.Node):
        return False
    return True

def matches_function_module_pattern(pattern, node, modules):
    if len(node.args) == 0:
        return False
    if node.op != "call_module":
        return False
    if not isinstance(node.target, str):
        return False
    if type(modules[node.target]) is not pattern[1]:
        return False
    if node.target not in modules:
        return False
    if len(node.args[0].users) > 1:
        return False
    if node.args[0].target is not pattern[0]:
        return False
    if node.args[0].op != "call_function" and node.args[0].op != "call_method":
        return False
    if not isinstance(node.args[0], torch.fx.Node) or not isinstance(node, torch.fx.Node):
        return False
    return True

# Works for length n patterns with n modules
def matches_module_pattern(pattern: Iterable[Type], node: fx.Node, modules: Dict[str, Any]):
    if len(node.args) == 0:
        return False
    if len(pattern) == 1:
       nodes: Tuple[fx.Node] = (node,)
    if len(pattern) == 2:
       nodes: Tuple[Any, fx.Node] = (node.args[0], node)
    for expected_type, current_node in zip(pattern, nodes):
        if not isinstance(current_node, fx.Node):
            return False
        if current_node.op != 'call_module':
            return False
        if not isinstance(current_node.target, str):
            return False
        if current_node.target not in modules:
            return False
        if type(modules[current_node.target]) is not expected_type:
            return False
    return True

def rmsnorm_pattern(pattern: Iterable[Type], node: fx.Node, modules: Dict[str, Any]):
    if len(node.args) == 0:
        return False
    #mul
    if node.op != "call_function":
        return False
    if node.target is not pattern[5]:
        return False
    if not isinstance(node, torch.fx.Node):
        return False
    #mul
    if node.args[0].op != "call_function":
        return False
    if node.args[0].target is not pattern[4]:
        return False
    if not isinstance(node.args[0], torch.fx.Node):
        return False
    if len(node.args[0].users) > 1:
       return False
    #rsqrt
    if node.args[0].args[1].op != "call_function":
        return False
    if node.args[0].args[1].target is not pattern[3]:
        return False
    if not isinstance(node.args[0].args[1], torch.fx.Node):
        return False
    if len(node.args[0].args[1].users) > 1:
        return False
    #add
    if node.args[0].args[1].args[0].op != "call_function":
        return False
    if node.args[0].args[1].args[0].target is not pattern[2]:
        return False
    if not isinstance(node.args[0].args[1].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[1].args[0].users) > 1:
       return False
    #mean
    if node.args[0].args[1].args[0].args[0].op != "call_method":
        return False
    if node.args[0].args[1].args[0].args[0].target is not pattern[1]:
        return False
    if not isinstance(node.args[0].args[1].args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[1].args[0].args[0].users) > 1:
       return False
    #pow
    if node.args[0].args[1].args[0].args[0].args[0].op != "call_method":
        return False
    if node.args[0].args[1].args[0].args[0].args[0].target is not pattern[0]:
        return False
    if not isinstance(node.args[0].args[1].args[0].args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[1].args[0].args[0].args[0].users) > 1:
       return False
    return True

def rmsnorm_pattern_llama(pattern: Iterable[Type], node: fx.Node, modules: Dict[str, Any]):
    if len(node.args) == 0:
        return False
    #mul
    if node.op != "call_function":
        return False
    if node.target is not pattern[7]:
        return False
    if not isinstance(node, torch.fx.Node):
        return False
    #type_as()
    if node.args[0].op != "call_method":
        return False
    if len(node.args[0].users) > 1:
        return False
    if node.args[0].target is not pattern[6]:
        return False
    #mul
    if node.args[0].args[0].op != "call_function":
        return False
    if node.args[0].args[0].target is not pattern[5]:
        return False
    if not isinstance(node.args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].users) > 1:
       return False
    #rsqrt
    if node.args[0].args[0].args[1].op != "call_function":
        return False
    if node.args[0].args[0].args[1].target is not pattern[4]:
        return False
    if not isinstance(node.args[0].args[0].args[1], torch.fx.Node):
        return False
    if len(node.args[0].args[0].args[1].users) > 1:
        return False
    #add
    if node.args[0].args[0].args[1].args[0].op != "call_function":
        return False
    if node.args[0].args[0].args[1].args[0].target is not pattern[3]:
        return False
    if not isinstance(node.args[0].args[0].args[1].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].args[1].args[0].users) > 1:
       return False
    #mean
    if node.args[0].args[0].args[1].args[0].args[0].op != "call_method":
        return False
    if node.args[0].args[0].args[1].args[0].args[0].target is not pattern[2]:
        return False
    if not isinstance(node.args[0].args[0].args[1].args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].args[1].args[0].args[0].users) > 1:
       return False
    #pow
    if node.args[0].args[0].args[1].args[0].args[0].args[0].op != "call_method":
        return False
    if node.args[0].args[0].args[1].args[0].args[0].args[0].target is not pattern[1]:
        return False
    if not isinstance(node.args[0].args[0].args[1].args[0].args[0].args[0], torch.fx.Node):
        return False
    if len(node.args[0].args[0].args[1].args[0].args[0].args[0].users) > 1:
       return False
    #float
    if node.args[0].args[0].args[1].args[0].args[0].args[0].args[0].op != "call_method":
       return False
    if node.args[0].args[0].args[1].args[0].args[0].args[0].args[0].target is not pattern[0]:
       return False
    if not isinstance(node.args[0].args[0].args[1].args[0].args[0].args[0].args[0], torch.fx.Node):
       return False
    if len(node.args[0].args[0].args[1].args[0].args[0].args[0].args[0].users) > 2:
       return False
    return True

def fuselayernorm_replaces_layernorm(gm: torch.fx.GraphModule):
    modules_patterns = [(torch.nn.LayerNorm,),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_pattern(pattern, node, modules):
                layer_norm = modules[node.target]
                new_node = torch.nn.FuseLayerNorm(layer_norm.normalized_shape)
                new_node.weight = torch.nn.Parameter(layer_norm.weight, layer_norm.weight.requires_grad)
                new_node.bias = torch.nn.Parameter(layer_norm.bias, layer_norm.bias.requires_grad)
                new_node.eps = layer_norm.eps
                new_node.elementwise_affine = layer_norm.elementwise_affine
                new_node.training = layer_norm.training
                replace_node_module(node, modules, new_node)
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_groupnorm_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [(torch.nn.GroupNorm,),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_pattern(pattern, node, modules):
                group_norm_node = node
                group_norm = modules[group_norm_node.target]
                num_groups = group_norm.num_groups
                num_channels = group_norm.num_channels
                eps = group_norm.eps
                fuse_node = torch.nn.FuseGroupNorm(num_groups=num_groups, num_channels=num_channels)
                fuse_node.eps = eps
                fuse_node.training = group_norm.training
                replace_node_module(node, modules, fuse_node.to('cuda'))
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_ln_dropout_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [(torch.nn.Dropout, torch.nn.LayerNorm),]
    function_patterns = [(F.dropout, F.layer_norm),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_pattern(pattern, node, modules):
                if len(node.args[0].users) > 1:
                    continue
                layer_norm = modules[node.target]
                dropout_node = node.args[0]
                dropout = modules[node.args[0].target]
                ln_dropout = torch.nn.FuseLnDropout(normalized_shape=layer_norm.normalized_shape)
                ln_dropout.weight = torch.nn.Parameter(layer_norm.weight, layer_norm.weight.requires_grad)
                ln_dropout.bias = torch.nn.Parameter(layer_norm.bias, layer_norm.bias.requires_grad)
                ln_dropout.eps = layer_norm.eps
                ln_dropout.p = dropout.p
                replace_node_module(node, modules, ln_dropout)
                node.args[0].replace_all_uses_with(node.args[0].args[0])
                gm.graph.erase_node(dropout_node)
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_celu_groupnorm_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [(torch.nn.CELU, torch.nn.GroupNorm),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_pattern(pattern, node, modules):
                if len(node.args[0].users) > 1:
                    continue
                group_norm_node = node
                celu_node = node.args[0]
                group_norm = modules[group_norm_node.target]
                celu = modules[celu_node.target]
                alpha = celu.alpha
                num_groups = group_norm.num_groups
                num_channels = group_norm.num_channels
                eps = group_norm.eps
                fuse_node = torch.nn.FuseCeluGroupNorm(num_groups=num_groups, num_channels=num_channels)
                fuse_node.weight = torch.nn.Parameter(group_norm.weight, group_norm.weight.requires_grad)
                fuse_node.bias = torch.nn.Parameter(group_norm.bias, group_norm.bias.requires_grad)
                fuse_node.alpha = alpha
                fuse_node.eps = eps
                replace_node_module(node, modules, fuse_node)
                node.args[0].replace_all_uses_with(node.args[0].args[0])
                gm.graph.erase_node(celu_node)  # delete celu
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_groupnorm_silu_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [(torch.nn.GroupNorm, torch.nn.SiLU),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_pattern(pattern, node, modules):
                if len(node.args[0].users) > 1:
                    continue
                silu_node = node
                group_norm_node = node.args[0]
                group_norm = modules[group_norm_node.target]
                num_groups = group_norm.num_groups
                num_channels = group_norm.num_channels
                eps = group_norm.eps
                fuse_node = torch.nn.FuseGroupNormSilu(num_groups=num_groups, num_channels=num_channels)
                fuse_node.weight = torch.nn.Parameter(group_norm.weight, group_norm.weight.requires_grad)
                fuse_node.bias = torch.nn.Parameter(group_norm.bias, group_norm.bias.requires_grad)
                fuse_node.eps = eps
                replace_node_module(node.args[0], modules, fuse_node)
                node.replace_all_uses_with(node.args[0])
                gm.graph.erase_node(silu_node)  # delete celu
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_dropout_add_fusion(gm: torch.fx.GraphModule):  ## 调式
    modules_patterns = [(torch.nn.Dropout, operator.add),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_function_pattern(pattern, node, modules):
                add_node = node
                dropout_node = node.args[0]
                dropout = modules[dropout_node.target]
                p = dropout.p
                args = list(dropout_node.args)
                args.append(list(add_node.args)[1])
                args = tuple(args)
                fuse_node = torch.nn.FuseDropoutAdd(rate=dropout.p)
                fuse_node.training = dropout.training
                target_name = node.args[0].target.split('self')[0] + "self_fuse_dropout_add"
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(add_node)  # delete add
                gm.graph.erase_node(dropout_node)  # delete dropout
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_ln_add_dropout_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [
        (torch.nn.Dropout, operator.add, torch.nn.LayerNorm),
    ]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_two_module_function_pattern(pattern, node, modules):
                dropout_node = node.args[0].args[0]
                add_node = node.args[0]
                layer_norm = modules[node.target]
                normalized_shape = layer_norm.normalized_shape
                eps = layer_norm.eps
                p = modules[dropout_node.target].p
                args_list = list(add_node.args)
                args_list_t = list(dropout_node.args)
                args_list_x = list(add_node.args)
                args_list_t.append(args_list_x[1])
                args = tuple(args_list_t)
                fuse_node = torch.nn.FuseLnAddDropout(normalized_shape=normalized_shape, p=p, eps=eps)
                fuse_node.training = layer_norm.training
                target_name = node.target
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(node)
                gm.graph.erase_node(add_node)
                gm.graph.erase_node(dropout_node)
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_bias_dropout_add_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [
        (operator.add, torch.nn.Dropout, operator.add),
    ]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_module_two_function_pattern(pattern, node, modules):
                dropout_node = node.args[0]
                bias_node = node.args[0].args[0]
                add_node = node
                dropout = modules[dropout_node.target]
                p = dropout.p
                args = list(bias_node.args)
                args.append(list(add_node.args)[1])
                args = tuple(args)
                fuse_node = torch.nn.FuseBiasDropoutAdd(droprate=p)
                fuse_node.training = dropout.training
                target_name = node.args[0].target.split('self')[0] + "self_bias_dropout_add"
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(add_node)  # delete add
                gm.graph.erase_node(dropout_node)  # delete dropout
                gm.graph.erase_node(bias_node)  # delete bias
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_ln_add_dropout_bias_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [
        (operator.add, torch.nn.Dropout, operator.add, torch.nn.LayerNorm),
    ]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_two_module_two_function_pattern(pattern, node, modules):
                layer_norm_node = node
                layer_norm = modules[layer_norm_node.target]
                dropout_node = node.args[0].args[0]
                add_node = node.args[0].args[0].args[0]
                bias_node = node.args[0]
                dropout = modules[dropout_node.target]
                normalized_shape = layer_norm.normalized_shape
                p = dropout.p
                eps = layer_norm.eps
                add_args = dropout_node.args[0].args
                bias_args = node.args[0].args
                args = list(add_args)
                args.append(bias_args[1])
                args = tuple(args)
                fuse_node = torch.nn.FuseLnAddDropoutBias(normalized_shape=normalized_shape, p=p, eps=eps)
                fuse_node.training = layer_norm.training
                target_name = node.target
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(node)  # delete layer_norm
                gm.graph.erase_node(bias_node)  # delete bias
                gm.graph.erase_node(dropout_node)  # delete dropout
                gm.graph.erase_node(add_node)  # delete add
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_bias_gelu_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [(operator.add, torch.nn.GELU,),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_function_module_pattern(pattern, node, modules):
                gelu_node = node
                add_node = node.args[0]
                gelu = modules[gelu_node.target]
                fuse_node = torch.nn.FuseBiasGelu()
                fuse_node.training = gelu.training
                target_name = node.target.split('self')[0] + "self_fuse_bias_gelu"
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=add_node.args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(gelu_node)
                gm.graph.erase_node(add_node)
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_bias_silu_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [(operator.add, torch.nn.SiLU,),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if matches_function_module_pattern(pattern, node, modules):
                silu_node = node
                add_node = node.args[0]
                silu = modules[silu_node.target]
                fuse_node = torch.nn.FuseBiasSwiGLU()
                fuse_node.training = silu.training
                target_name = node.target.split('self')[0] + "self_fuse_bias_silu"
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=add_node.args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(silu_node)
                gm.graph.erase_node(add_node)
    gm.graph.lint()
    gm.recompile()
    return gm

def fuse_rmsnorm_fusion(gm: torch.fx.GraphModule):
    modules_patterns = [("pow", "mean", operator.add, torch.rsqrt, operator.mul, operator.mul),]
    llama_patterns = [("float", "pow", "mean", operator.add, torch.rsqrt, operator.mul, "type_as", operator.mul),]
    modules = dict(gm.named_modules())
    for pattern in modules_patterns:
        for node in gm.graph.nodes:
            if rmsnorm_pattern(pattern, node, modules):
                mul_node = node
                mul_1_node = node.args[0]
                rsqrt_node = mul_1_node.args[1]
                add_node = rsqrt_node.args[0]
                mean_node = add_node.args[0]
                pow_node = mean_node.args[0]
                if pow_node.args[0] != mul_1_node.args[0]:
                    return gm
                args_1 = list(pow_node.args)[0]
                eps = list(add_node.args)[1]
                args_2 = list(mul_node.args)[1]
                args = (args_1, args_2)
                fuse_node = torch.nn.RMSNorm(eps=eps)
                target_name = "rmsnorm_" + node.name.split("_")[-1]
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(mul_node)
                gm.graph.erase_node(mul_1_node)
                gm.graph.erase_node(rsqrt_node)
                gm.graph.erase_node(add_node)
                gm.graph.erase_node(mean_node)
                gm.graph.erase_node(pow_node)
    gm.graph.lint()
    for pattern in llama_patterns:
        for node in gm.graph.nodes:
            if rmsnorm_pattern_llama(pattern, node, modules):
                mul_node = node
                type_as_node = node.args[0]
                mul_1_node = type_as_node.args[0]
                rsqrt_node = mul_1_node.args[1]
                add_node = rsqrt_node.args[0]
                mean_node = add_node.args[0]
                pow_node = mean_node.args[0]
                float_node = pow_node.args[0]
                if pow_node.args[0] != mul_1_node.args[0]:
                    return gm
                args_1 = list(float_node.args)[0]
                eps = list(add_node.args)[1]
                args_2 = list(mul_node.args)[1]
                args = (args_1, args_2)
                fuse_node = torch.nn.RMSNorm(eps=eps)
                target_name = "rmsnorm_" + node.name.split("_")[-1]
                print(f"target_name : {target_name}")
                gm.add_submodule(target_name, fuse_node.to('cuda'))
                with gm.graph.inserting_before(node):
                    new_node = gm.graph.call_module(module_name=target_name, args=args)
                node.replace_all_uses_with(new_node)
                gm.graph.erase_node(mul_node)
                gm.graph.erase_node(type_as_node)
                gm.graph.erase_node(mul_1_node)
                gm.graph.erase_node(rsqrt_node)
                gm.graph.erase_node(add_node)
                gm.graph.erase_node(mean_node)
                gm.graph.erase_node(pow_node)
                gm.graph.erase_node(float_node)
    gm.graph.lint()
    gm.recompile()
    return gm
