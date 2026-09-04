import builtins
import io
import json
import operator
import os
import re

from . import irVisitor
import copy
from .ir import *
from constraintflow.lib.globals import dummy_mode, reuse_mode, load_capture, capture_exists, inductor_mode, fused_flow, sroa

def fused_build():
    """True only on the reuse pass of a --fused-flow build, where flow() is emitted."""
    return reuse_mode.get_flag() and fused_flow.get_flag()


def sroa_build():
    """True only on the reuse pass of an --sroa build."""
    return fused_build() and sroa.get_flag()


# Matches a torch.tensor(...) call whose contents are a pure numeric literal
# (no identifiers), e.g. torch.tensor([1, 6272], dtype=torch.int64) or
# torch.tensor([1.0, 1.0]). Anything referencing a runtime variable -- a layer
# size, a poly_size -- fails this match and is left inline, since only a pure
# literal is safe to dedupe into a module-level constant shared across sites.
_LITERAL_TENSOR_RE = re.compile(r'^torch\.tensor\(\[[0-9,\.\-\s\[\]]*\](?:, dtype=torch\.\w+)?\)$')

# One prefix per payload kind: tier class is prefix+'Sparse', leaf is prefix+kind.
SPARSE_TIER = {'FloatTensorSparse': 'FloatTensor', 'BoolTensorSparse': 'BoolTensor',
               'BoolScalarSparse': 'BoolScalar', 'ScalarSparse': 'FloatScalar'}

# The arm of the real SparseBlock.__init__ that each tier fixes statically.
SPARSE_PAYLOAD_INIT = {
    'FloatTensorSparse': 'block.to(device_mode.get_device()).type(torch.float)',
    'BoolTensorSparse': 'block.to(device_mode.get_device())',
    'BoolScalarSparse': 'block',
    'ScalarSparse': 'float(block)',
}

SPARSE_TENSOR_PAYLOAD = {'FloatTensorSparse': True, 'BoolTensorSparse': True,
                         'BoolScalarSparse': False, 'ScalarSparse': False}

BLOCK_FIELDS = {
    'DenseBlock': ('D', ('batch_size',)),
    'ConstBlock': ('C', ()),
    'RepeatBlock': ('R', ('repeat_dims', 'only_one_repeat')),
    'DiagonalBlock': ('Diag', ('diag_index', 'batch_size')),
    'KernelBlock': ('K', ('ix', 'iy', 'ox', 'oy', 'sx', 'sy', 'px', 'py',
                          'kx', 'ky', 'num_channels', 'num_kernels')),
    'PatchesBlock': ('P', ('ix', 'iy', 'ox', 'oy', 'sx', 'sy', 'px', 'py',
                           'kx', 'ky', 'num_channels', 'num_kernels')),
}

_BATCH_SIZE_RE = re.compile(r'\bbatch_size\b')


class CodeGen(irVisitor.IRVisitor):
    def __init__(self,folder):
        self.folder = folder 
        if self.folder.endswith('/'):
            self.folder = self.folder[:-1]
        self.main_file = self.folder + '/main.py'
        self.transformers_file = self.folder + '/transformers.py'
        self.shape = None
        open(self.main_file, "w").close()
        open(self.transformers_file, "w").close()

        self.file = open(self.main_file, "a")
        self.indent = 0

        self.current_layer_index = None

        self.write("import sys")
        self.write("import os")
        self.write("from constraintflow.lib.spec import *")
        self.write("from constraintflow.lib.flow_sparse import Flow" +
                   (", get_dense_inlined" if fused_flow.get_flag() else ""))
        self.write("from constraintflow.lib.abs_elem import Abs_elem_sparse")
        self.write("from constraintflow.lib.symexp import *")
        self.write("from constraintflow.lib.globals import save_capture, inductor_mode")
        self.write("from transformers import *")
        self.write("\n")
        # self.write("torch.cuda.reset_peak_memory_stats()")
        self.write("def run(network_file, batch_size, eps, dataset_X, dataset_y, dataset, train, print_intermediate_results, no_sparsity):")
        
        self.indent += 1
        self.visited = set()

        self.counter = 0

        self.used_block_classes = set()

        # Reuse mode inlines its own class; normal mode imports the real one.
        self.polyexp_cls = 'JitPolyExpSparse' if reuse_mode.get_flag() else 'PolyExpSparse'

        # literal torch.tensor(...) text -> hoisted module-level name (_K<n>).
        # Populated by _const, flushed to jit_constants.py by finish().
        self.const_pool = {}

        # Numbers the temporaries _hoist_if_complex introduces.
        self._rebind_tmp_counter = 0

        # Module-level @torch.compiler.disable helpers, one per in-place write
        # into a torch.as_strided(...) view (PatchesBlock/KernelBlock's Conv2D
        # densification). Correct in eager mode, but Inductor silently drops
        # some of these writes when compiled inline, undercounting DeepZ's
        # generator terms and producing unsound bounds. Must be module-level
        # (not a nested closure) because Dynamo refuses to trace defining and
        # decorating a function inline, so the view/value are passed in as
        # plain arguments instead of closed over.
        self.view_write_helpers = []
        # Set while generating a method that used a view-write helper above.
        # torch.compiler.disable forces a graph break, which fullgraph=True
        # treats as a hard error, so that method must compile with
        # fullgraph=False instead.
        self._method_has_view_write = False
        # Sticky across all methods: decides flow()'s fullgraph in a --fused-flow build.
        self._any_view_write = False
        # (op, layer_index) in emission order, for the generated flow().
        self.layer_calls = []

    # Llist params the fused flow passes as None; a body that reads one would be miscompiled.
    _LLIST_PARAMS = ('prev', 'curr', 'prev1', 'prev2')

    def _check_no_llist_params(self, opStmtIr, layer_index, body_text):
        """Reject a specialized body that still reads a Llist parameter."""
        body = body_text.split('\n', 1)[1] if '\n' in body_text else ''
        for name in self._LLIST_PARAMS:
            if name in opStmtIr.params and re.search(r'\b' + name + r'\b', body):
                raise RuntimeError(
                    f"fused flow: {opStmtIr.op}_{layer_index} still reads the Llist parameter "
                    f"{name!r}, which flow() does not reconstruct")

    def emit_flow(self, node):
        """Emit the layer-unrolled flow() that replaces the interpretive Flow.flow."""
        certifier = next(n.transformer for n in node.irNodes if isinstance(n, IrFlow))
        layers = {row['layer']: row for row in load_capture('jit_flow/flow.json')}
        calls = sorted(self.layer_calls, key=lambda c: c[0])
        if sorted(layers) != [c[0] for c in calls]:
            raise RuntimeError(
                f"fused flow: flow.json covers layers {sorted(layers)} but the specialized "
                f"methods cover {[c[0] for c in calls]}")
        fields = list(self.shape.keys())
        state = ', '.join('d_' + key for key in fields)
        # Each method returns its abstract shape followed by the new threaded state.
        shape_out = ', '.join('s_' + key for key in fields)

        self.indent = 0
        self.write('')
        self.write('_T = ' + certifier + '()')
        if inductor_mode.get_flag():
            self.write('@torch.compile(fullgraph=' + str(not self._any_view_write) + ', backend="inductor")')
        self.write('def flow(abs_elem, batch_size):')
        self.indent += 1
        self.write(state + ' = ' + ', '.join("abs_elem.d['" + key + "']" for key in fields))
        for layer_index, op, params in calls:
            row = layers[layer_index]
            args = []
            for name in params:
                if name in self._LLIST_PARAMS:
                    args.append('None')
                elif name in ('poly_size', 'curr_size', 'prev_size', 'input_size'):
                    args.append(str(row[name]))
                else:
                    args.append(name)
            self.write(shape_out + ', ' + state + ' = _T.' + op + '_' + str(layer_index)
                       + '(' + ', '.join(args) + ', layer_index = ' + str(layer_index) + ')')
        self.write('return ' + shape_out)
        self.indent -= 1
        self.write('')

    def emit_sroa_flow(self, node):
        """Emit explode_inputs() and the scalarized flow()."""
        real_file = self.file
        self.file = io.StringIO()
        self.indent = 1
        self._method_has_view_write = False
        self.visit(node.flow_block)
        body_text = self.file.getvalue()
        self.file = real_file
        params = list(node.flow_params)
        if _BATCH_SIZE_RE.search(body_text):
            # shapes that stayed symbolic render it as raw text in a traced
            # total_size, so the body is the only place it can be spotted
            params.append(('batch_size', 'batch_size'))
        self.indent = 0
        self.write('')
        # No leading underscore: `from transformers import *` drops those.
        self.write('def explode_inputs(abs_elem, batch_size):')
        self.indent += 1
        self.write('return (' + ', '.join(path for _, path in params) + ',)')
        self.indent -= 1
        self.write('')
        if inductor_mode.get_flag():
            self.write('@torch.compile(fullgraph=' + str(not self._method_has_view_write)
                       + ', backend="inductor")')
        self.write('def flow(' + ', '.join(name for name, _ in params) + '):')
        self.file.write(body_text)
        self.write('')

    def _const(self, text):
        """Intern a literal torch.tensor(...) expression into the shared constant
        pool (reuse mode only) and return the reference to use in its place.
        Non-literal text -- and anything outside reuse mode -- passes through
        unchanged, so this is safe to call on every torch.tensor(...) site."""
        if not reuse_mode.get_flag() or not _LITERAL_TENSOR_RE.match(text):
            return text
        name = self.const_pool.get(text)
        if name is None:
            # No leading underscore: `from jit_constants import *` (in
            # transformers.py's header) silently drops underscore-prefixed
            # names under Python's wildcard-import rules.
            name = 'JITCONST' + str(len(self.const_pool))
            self.const_pool[text] = name
        return name

    def finish(self):
        """Flush the hoisted constant pool to <folder>/jit_constants.py. Called
        once after visit(ir) completes, since the pool is only complete then."""
        if not reuse_mode.get_flag():
            return
        path = self.folder + '/jit_constants.py'
        with open(path, 'w') as f:
            f.write('import torch\n\n')
            for text, name in self.const_pool.items():
                f.write(name + ' = ' + text + '\n')
        if sroa_build():
            self._check_flow_is_closed()

    def _check_flow_is_closed(self):
        """Every name flow() reads must be a parameter, a local, or a module global.
        A leftover ambient name compiles fine and only fails inside dynamo."""
        import ast
        source = open(self.transformers_file).read()
        tree = ast.parse(source)
        globals_, flow = set(dir(builtins)), None
        for node in tree.body:
            if isinstance(node, (ast.Import, ast.ImportFrom)):
                globals_.update((a.asname or a.name).split('.')[0] for a in node.names)
            elif isinstance(node, (ast.FunctionDef, ast.ClassDef)):
                globals_.add(node.name)
                if node.name == 'flow':
                    flow = node
            elif isinstance(node, ast.Assign):
                globals_.update(t.id for t in ast.walk(node)
                                if isinstance(t, ast.Name) and isinstance(t.ctx, ast.Store))
        if flow is None:
            return
        bound = {a.arg for a in flow.args.args}
        loads = set()
        for node in ast.walk(flow):
            if isinstance(node, ast.Name):
                (bound if isinstance(node.ctx, ast.Store) else loads).add(node.id)
        free = sorted(loads - bound - globals_)
        if free:
            raise RuntimeError('sroa: flow() reads unbound ' + ', '.join(free)
                               + '; it must be a flow parameter')

    def _hoist_if_complex(self, expr_text):
        """visitIrExpandSymExp/visitIrSetBlockTotalShapeLastDim need to reference
        their base object twice (once to mutate, once to read the mutated
        total_size/total_shape back) and then a third time via their return
        value. When symexpCount/subexp_inlining leaves that base inlined as a
        full expression -- typically a SymExpSparse(...)/JitSparseTensor(...)
        construction, not a bare name -- emitting it verbatim at each of those
        sites reconstructs the whole object 2-3 times per rebind. Bind it to a
        fresh local first so it is only built once; a bare name/attribute
        chain (no call in it) is already cheap to repeat and is returned as-is."""
        if '(' not in expr_text:
            return expr_text
        tmp = 'rebind_tmp_' + str(self._rebind_tmp_counter)
        self._rebind_tmp_counter += 1
        self.write(tmp + ' = ' + expr_text)
        return tmp


    def _ttb_comment(self, node):
        if dummy_mode.get_flag() or reuse_mode.get_flag():
            return ' #' + str(node.ttb_counter)
        return ''

    # This function is used to get the branch information for a tuple (block_id, layer_index) from the jit file.
    def get_profiled_branch(self, block_id):
        if not reuse_mode.get_flag():
            return None
        if self.current_layer_index is None:
            return None
        rel_path = f"jit_branch/branch_{self.current_layer_index}_{block_id}.json"
        if not capture_exists(rel_path):
            raise Exception(f"Profiled branch data not found for block_id {block_id} at {rel_path}")
        json_obj = load_capture(rel_path)
        taken = json_obj["taken"]
        if taken in ["then", "else"]:
            return taken
        return None


    def write(self, str, flag=True):
        self.file.write('\t'*self.indent + str)
        if flag:
            self.file.write('\n')

    def write_expr(self, str, flag=True):
        self.file.write(str)
        if flag:
            self.file.write('\n')


    def open(self, file):
        self.file.close()
        self.file = open(file, "a")

    def visitIrProgram(self, node):
        self.shape = node.shape
        temp_shape = copy.deepcopy(self.shape)
        temp_shape['llist'] = 'bool'
        temp_dict = "{"
        key = 'llist'
        i = 0

        temp_dict += "\'" + key + "\' : " + key + ', '
        for i, key in enumerate(node.shape.keys()):
            temp_dict += "\'" + key + "\' : " + key 
            if i < len(node.shape.keys())-1:
                temp_dict += ", "
        temp_dict += '}'


        self.write("network, l, u, L, U, Z, llist = get_network_and_input_spec(network_file, batch_size, dataset_X, dataset_y, dataset, eps=eps, train=train, no_sparsity=no_sparsity)")
        self.write("abs_elem = Abs_elem_sparse(" + temp_dict + ", " + str(temp_shape) + ", network, batch_size=batch_size, no_sparsity=no_sparsity)")
        



        # GENERATE TRANSFORMERS
        self.open(self.transformers_file)
        self.indent = 0
        self.write('import gc')
        self.write('import json')
        self.write('import os')
        self.write('import torch')
        # self.write("torch.set_float32_matmul_precision('high')")
        self.write('import operator')
        self.write('from constraintflow.lib.globals import device_mode')
        if not reuse_mode.get_flag():
            self.write('from constraintflow.lib.polyexp import PolyExpSparse')
        if reuse_mode.get_flag():
            self.write('from constraintflow.lib.symexp import SymExpSparse')
            self.write('from constraintflow.gbcsr.sparse_block import col2im_columns')
            # self.write('from constraintflow.lib.symexp import get_new_eps')
            # self.write('from constraintflow.gbcsr.op_helper import binary_to_identity_unary')

        else:
            self.write('from constraintflow.lib.symexp import *')
        if reuse_mode.get_flag():
            self.write('import operator')
            self.write('import torch.nn.functional as F')
            self.write('from jit_constants import *')
            # self.write('from constraintflow.gbcsr.tensor_ops import *')
        else:
            self.write('from constraintflow.gbcsr.sparse_tensor import SparseTensor')
        self.write('from constraintflow.lib.llist import Llist')
        if not reuse_mode.get_flag():
            self.write('from constraintflow.gbcsr.tensor_ops import *')
        for i, transformer_name in enumerate(node.tstore.keys()):
            if sroa_build():
                break
            self.write('class ' + transformer_name + ':')
            self.indent += 1

            transformerIr = node.tstore[transformer_name]

            for j, opStmtIr in enumerate(transformerIr):
                param_list = ', '.join(opStmtIr.params)
                # Under --fused-flow the specialized methods take the threaded state too.
                layerwise_list = ', '.join(opStmtIr.layerwise_params or opStmtIr.params)
                if opStmtIr.layerwise_cfgs is None:
                    self.write('def ' + opStmtIr.op + '(self, ' + param_list + ', layer_index = None):')
                    self.indent += 1
                    # self.write('torch.cuda.memory._record_memory_history(')
                    # self.indent += 1
                    # self.write('max_entries=1000000')
                    # self.indent -= 1
                    # self.write(')')

                    cfg = opStmtIr.cfg
                    self.visit(cfg.ir[cfg.entry_node])
                    self.indent -= 1
                    self.write('', True)
                else:
                    self.write('def ' + opStmtIr.op + '(self, ' + param_list + ', layer_index = None):')
                    self.indent += 1
                    # self.write('torch.cuda.memory._record_memory_history(')
                    # self.indent += 1
                    # self.write('max_entries=1000000')
                    # self.indent -= 1
                    # self.write(')')
                    if opStmtIr.layerwise_params is None:
                        for layer_index in opStmtIr.layerwise_cfgs.keys():
                            self.write('if layer_index == ' + str(layer_index) + ':')
                            self.indent += 1
                            self.write('return self.' + opStmtIr.op + '_' + str(layer_index) + '(' + param_list + ', layer_index = layer_index)')
                            self.indent -= 1
                        self.write("raise RuntimeError(f'no specialized kernel for " + opStmtIr.op + " at layer {layer_index}')")
                    else:
                        # Fused builds drive the specialized methods from flow(), not from here.
                        self.write("raise RuntimeError('" + opStmtIr.op + ": this is a --fused-flow build; call flow() instead')")
                    self.indent -= 1
                    self.write('')

                    for layer_index in opStmtIr.layerwise_cfgs.keys():
                        self.layer_calls.append((layer_index, opStmtIr.op, opStmtIr.layerwise_params))
                        # Buffer the body first so we know, after visiting it,
                        # whether it used a view-write helper before deciding
                        # fullgraph=True vs False for this method's decorator.
                        self._method_has_view_write = False
                        real_file = self.file
                        self.file = io.StringIO()
                        self.write('def ' + opStmtIr.op + '_' + str(layer_index) + '(self, ' + layerwise_list + ', layer_index = None):')
                        self.indent += 1
                        self.write('while_iteration = -1')
                        cfg = opStmtIr.layerwise_cfgs[layer_index]
                        self.current_layer_index = layer_index
                        self.visit(cfg.ir[cfg.entry_node])
                        self.indent -= 1
                        self.write('', True)
                        body_text = self.file.getvalue()
                        self.file = real_file
                        self._any_view_write |= self._method_has_view_write
                        # Fused builds carry one decorator on flow() instead of one per method.
                        if inductor_mode.get_flag() and not fused_build():
                            fullgraph = not self._method_has_view_write
                            self.write('@torch.compile(fullgraph=' + str(fullgraph) + ', backend="inductor")')
                        if fused_build():
                            self._check_no_llist_params(opStmtIr, layer_index, body_text)
                        self.file.write(body_text)
            self.indent -=1

        if sroa_build():
            self.emit_sroa_flow(node)
        elif fused_build():
            self.emit_flow(node)

        if reuse_mode.get_flag():
            # Defined after use; names resolve when the methods are called.
            self.indent = 0
            for helper_src in self.view_write_helpers:
                self.write(helper_src, False)
                self.write('')
        if reuse_mode.get_flag() and not (sroa_build() and not self.used_block_classes):
            self.indent = 0
            self.write('class JitSparseTensor:')
            self.indent += 1
            self.write('__slots__ = ("start_indices", "blocks", "dims", "total_size", "end_indices", "type", "dense_const", "delete_indices", "num_blocks")')
            self.write('def __init__(self, start_indices, blocks, dims, total_size, end_indices, type, dense_const, delete_indices):')
            self.indent += 1
            for field in ('start_indices', 'blocks', 'dims', 'total_size', 'end_indices', 'type', 'dense_const', 'delete_indices'):
                self.write('self.' + field + ' = ' + field)
            self.write('self.num_blocks = len(start_indices)')
            self.indent -= 1
            # These preserve structure entirely; only payload and dense_const change.
            self.write('def float(self):')
            self.indent += 1
            self.write('return JitSparseTensor(self.start_indices, [b.float() for b in self.blocks], self.dims, self.total_size, self.end_indices, float, float(self.dense_const), self.delete_indices)')
            self.indent -= 1
            self.write('def check_dense(self):')
            self.indent += 1
            self.write('t = 0')
            self.write('for i in range(self.num_blocks):')
            self.indent += 1
            self.write('p = 1')
            self.write('for d in self.blocks[i].total_shape.tolist():')
            self.indent += 1
            self.write('p = p * d')
            self.indent -= 1
            self.write('t = t + p')
            self.indent -= 1
            self.write('q = 1')
            self.write('for d in self.total_size.tolist():')
            self.indent += 1
            self.write('q = q * d')
            self.indent -= 1
            self.write('return not (t < q)')
            self.indent -= 1
            self.write('def increase_size(self, start_index, new_total_size):')
            self.indent += 1
            self.write('res_start_indices = []')
            self.write('res_end_indices = []')
            self.write('res_blocks = []')
            self.write('for i in range(self.num_blocks):')
            self.indent += 1
            self.write('res_start_indices.append(start_index + self.start_indices[i])')
            self.write('res_end_indices.append(start_index + self.end_indices[i])')
            self.write('res_blocks.append(self.blocks[i].copy())')
            self.indent -= 1
            self.write('return JitSparseTensor(res_start_indices, res_blocks, self.dims, new_total_size, res_end_indices, self.type, self.dense_const, self.delete_indices)')
            self.indent -= 2

            self.write('class ' + self.polyexp_cls + ':')
            self.indent += 1
            self.write('__slots__ = ("network", "mat", "const")')
            self.write('def __init__(self, network, mat, const):')
            self.indent += 1
            for field in ('network', 'mat', 'const'):
                self.write('self.' + field + ' = ' + field)
            self.indent -= 2

            self.write('class JitSparseBlock:')
            self.indent += 1
            self.write('__slots__ = ("block", "total_shape")')
            self.indent -= 1

            # float() names another leaf, so both float targets must exist for every kind used.
            leaves = set(self.used_block_classes)
            leaves |= {(kind, 'FloatTensorSparse') for kind, t in self.used_block_classes
                       if SPARSE_TENSOR_PAYLOAD[t]}
            leaves |= {(kind, 'ScalarSparse') for kind, t in self.used_block_classes
                       if not SPARSE_TENSOR_PAYLOAD[t]}

            # Each tier owns one payload representation, so leaves carry only geometry.
            for sparse_block_type in sorted({t for _, t in leaves}):
                self.write('class ' + SPARSE_TIER[sparse_block_type] + 'Sparse(JitSparseBlock):')
                self.indent += 1
                self.write('__slots__ = ()')
                self.write('def __init__(self, block, total_shape):')
                self.indent += 1
                self.write('self.block = ' + SPARSE_PAYLOAD_INIT[sparse_block_type])
                self.write('self.total_shape = total_shape')
                self.indent -= 2

            for kind, sparse_block_type in sorted(leaves):
                block_type, fields = BLOCK_FIELDS[kind]
                tier = SPARSE_TIER[sparse_block_type]
                is_tensor = SPARSE_TENSOR_PAYLOAD[sparse_block_type]
                float_tier = SPARSE_TIER['FloatTensorSparse' if is_tensor else 'ScalarSparse']
                rest = ''.join(', self.' + f for f in fields)
                self.write('class ' + tier + kind + '(' + tier + 'Sparse):')
                self.indent += 1
                self.write('__slots__ = (' + ''.join('"' + f + '", ' for f in fields) + ')')
                self.write("block_type = '" + block_type + "'")
                self.write('def __init__(self, block, total_shape' + ''.join(', ' + f for f in fields) + '):')
                self.indent += 1
                self.write(tier + 'Sparse.__init__(self, block, total_shape)')
                for f in fields:
                    self.write('self.' + f + ' = ' + f)
                self.indent -= 1
                self.write('def float(self):')
                self.indent += 1
                payload = 'self.block.float()' if is_tensor else 'float(self.block)'
                self.write('return ' + float_tier + kind + '(' + payload + ', self.total_shape' + rest + ')')
                self.indent -= 1
                self.write('def copy(self):')
                self.indent += 1
                self.write('return ' + tier + kind + '(' + ('self.block.clone()' if is_tensor else 'self.block') + ', self.total_shape' + rest + ')')
                self.indent -= 2

        self.open(self.main_file)
        for i in range(len(node.irNodes)):
            self.visit(node.irNodes[i])

    def visitIrBlock(self, node):
        if not node in self.visited:
            self.visited.add(node)
            ir_list = node.children
            for counter, i in enumerate(ir_list):
                self.visit(i)
            if node.inner_jump != None:
                if len(node.inner_jump)==3:
                    cond = self.visit(node.inner_jump[0])
                    block_id = node.block_id
                    profiled_branch = self.get_profiled_branch(block_id)
                    if profiled_branch == 'then':
                        self.visit(node.inner_jump[1])
                    elif profiled_branch == 'else':
                        self.visit(node.inner_jump[2])
                    else:
                        self.write('if(' + str(cond) + '):')
                        self.indent += 1
                        if block_id is not None:
                            self.write('if dummy_mode:')
                            self.indent += 1
                            self.write('save_capture("jit_branch/branch_" + str(layer_index) + "_' + str(block_id) + '.json", {"taken": "then"})')
                            self.indent -= 1
                        self.visit(node.inner_jump[1])
                        self.indent -= 1
                        self.write('else:')
                        self.indent += 1
                        if block_id is not None:
                            self.write('if dummy_mode:')
                            self.indent += 1
                            self.write('save_capture("jit_branch/branch_" + str(layer_index) + "_' + str(block_id) + '.json", {"taken": "else"})')
                            self.indent -= 1
                        self.visit(node.inner_jump[2])
                        self.indent -= 1
                elif not isinstance(node.inner_jump[1], IrWhileBlock):
                    cond = self.visit(node.inner_jump[0])
                    self.write('if(' + str(cond) + '):')
                    self.indent += 1
                    self.visit(node.inner_jump[1])
                    self.indent -= 1
                else:
                    cond = self.visit(node.inner_jump[0])
                    self.write('while_iteration = -1')
                    self.write('while(' + str(cond) + '):')
                    self.indent += 1
                    self.write('while_iteration += 1')
                    # self.write('print(\'while_iteration\', while_iteration)')
                    self.visit(node.inner_jump[1])
                    self.indent -= 1
                    self.write('if dummy_mode:')
                    self.indent += 1
                    self.write('json_obj = {"num_iterations": while_iteration}')
                    self.write('save_capture("jit_while/while_iterations_layer_" + str(layer_index) + "_while_" + str(' + str(node.inner_jump[1].while_number) + ') + ".json", json_obj)')
                    self.indent -= 1
            if node.jump != None:
                self.visit(node.jump[1])

    def visitIrAssignment(self, node):
        var = str(self.visit(node.children[0]))
        expr = str(self.visit(node.children[1]))
        self.write(var + ' = ' + expr )
        # node.counter = self.counter
        # self.counter += 1

    # For the del statements
    # Currently not used. 
    def visitIrDel(self, node):
        # self.write('del ' + ', '.join(node.var_names))
        # self.write('gc.collect()')
        # self.write('torch.cuda.empty_cache()')
        pass

    def visitIrBreak(self, node):
        self.write('break')

    def visitIrTransRetBasic(self, node):
        # self.write('try:')
        # self.indent += 1
        # self.write('torch.cuda.memory._dump_snapshot(f"memory_usage_{layer_index}.pickle")')
        # self.indent -= 1
        # self.write('except:')
        # self.indent += 1
        # self.write('raise Exception("CUDA memory snapshot failed. This can happen if the file prefix is too long or if there are issues with the CUDA setup. Please check your CUDA configuration and ensure that the file prefix is valid.")')
        # self.indent -= 1
        
        exprs = []
        for i in range(len(node.children)):
            expr = self.visit(node.children[i])
            exprs.append(expr)
        ret_expr = 'return '
        for i in range(len(node.children)-1):
            ret_expr += exprs[i]
            ret_expr += ', '
        ret_expr += exprs[-1] + ', '
        self.write(ret_expr)

    def visitIrTransRetIf(self, node):
        cond = self.visit(node.children[0])
        self.write('if(' + cond + '):')
        self.indent += 1
        if len(node.children[1])>0:
            for i in node.children[1]:
                self.visit(i)
        else:
            self.write('pass')
        self.indent -= 1
        if len(node.children[2])>0:
            self.write('else:')
            self.indent += 1
            for i in node.children[1]:
                self.visit(i)
            self.indent -= 1
        else:
            self.write('pass')
        self.write('return')

    def visitIrIte(self, node):
        cond = self.visit(node.children[0])
        self.write('if(' + cond + '):')
        self.indent += 1
        if len(node.children[1])>0:
            for i in node.children[1]:
                self.visit(i)
        else:
            self.write('pass')
        self.indent -= 1
        if len(node.children[2])>0:
            self.write('else:')
            self.indent += 1
            for i in node.children[1]:
                self.visit(i)
            self.indent -= 1

    # def visitIrWhile(self, node):
    #     cond = self.visit(node.children[0])
    #     self.write('while(' + str(cond) + '):')
    #     self.indent += 1
    #     for ir in node.children[1:]:
    #         self.visit(ir)
    #     self.indent -= 1
    

    def visitIrStr(self, node):
        return node
    
    def visitIrConst(self, node):
        return str(node.const)

    def visitList(self, node):
        res = '['
        for i, child in enumerate(node):
            if i > 0:
                res += ', '
            res += self.visit(child)
        res += ']'
        return res

    def renderTraceIndex(self, index):
        parts = []
        for item in index:
            if isinstance(item, list):
                if len(item) == 2:
                    parts.append(self.visit(item[0]) + ':' + self.visit(item[1]))
                else:
                    parts.append(self.visit(item))
            elif isinstance(item, str):
                parts.append(item)
            elif isinstance(item, int) and item == 0:
                parts.append(':')
            else:
                parts.append(self.visit(item))
        return ', '.join(parts)

    def visitIrSparseTensor(self, node):
        start_indices = '[' + ', '.join(
            x if isinstance(x, str) else self._const('torch.tensor(' + str(x.tolist()) + ', dtype=torch.int64)')
            for x in node.start_indices) + ']'
        end_indices = '[' + ', '.join(
            x if isinstance(x, str) else self._const('torch.tensor(' + str(x.tolist()) + ', dtype=torch.int64)')
            for x in node.end_indices) + ']'
        total_size = node.total_size if isinstance(node.total_size, str) else self._const('torch.tensor(' + str(node.total_size.tolist()) + ', dtype=torch.int64)')
        # An empty block list is a plain [], not an IR node.
        blocks = '[]' if isinstance(node.children[0], list) else self.visit(node.children[0])
        # repr of these three does not parse back.
        dense_const = repr(node.dense_const)
        if dense_const in ('inf', '-inf', 'nan'):
            dense_const = "float('" + dense_const + "')"

        return ('JitSparseTensor(' + start_indices + ', ' + blocks + ', ' + str(node.dims) + ', '
                + total_size + ', ' + end_indices + ', ' + node.type.__name__ + ', '
                + dense_const + ', ' + str(node.delete_indices) + ')')

    def visitIrConstBlock(self, node):
        self.used_block_classes.add(('ConstBlock', node.sparse_block_type))
        return (SPARSE_TIER[node.sparse_block_type] + 'ConstBlock('
                + self.visit(node.children[0]) + ', ' + self._const(node.total_shape) + ')')

    def visitIrPatchesBlock(self, node):
        self.used_block_classes.add(('PatchesBlock', node.sparse_block_type))
        return (SPARSE_TIER[node.sparse_block_type] + 'PatchesBlock('
                + self.visit(node.children[0]) + ', ' + self._const(node.total_shape) + ', '
                + str(node.ix) + ', ' + str(node.iy) + ', '
                + str(node.ox) + ', ' + str(node.oy) + ', '
                + str(node.sx) + ', ' + str(node.sy) + ', '
                + str(node.px) + ', ' + str(node.py) + ', '
                + str(node.kx) + ', ' + str(node.ky) + ', '
                + str(node.num_channels) + ', ' + str(node.num_kernels) + ')')

    def visitIrRepeatBlock(self, node):
        self.used_block_classes.add(('RepeatBlock', node.sparse_block_type))
        return (SPARSE_TIER[node.sparse_block_type] + 'RepeatBlock('
                + self.visit(node.children[0]) + ', ' + self._const(node.total_shape) + ', '
                + self._const(node.repeat_dims) + ', ' + str(node.only_one_repeat) + ')')

    def visitIrDiagonalBlock(self, node):
        self.used_block_classes.add(('DiagonalBlock', node.sparse_block_type))
        return (SPARSE_TIER[node.sparse_block_type] + 'DiagonalBlock('
                + self.visit(node.children[0]) + ', ' + self._const(node.total_shape) + ', '
                + str(node.diag_index) + ', ' + str(node.batch_size) + ')')

    def visitIrTorchDiagonal(self, node):
        input_expr = self.visit(node.children[0])
        return (
            'torch.diagonal(' + input_expr
            + ', dim1=' + str(node.dim1)
            + ', dim2=' + str(node.dim2) + ')'
        )

    def visitIrTorchPermute(self, node):
        input_expr = self.visit(node.children[0])
        perm_args = ', '.join(str(i) for i in node.permutation)
        return input_expr + '.permute(' + perm_args + ')'

    def visitIrTorchTranspose(self, node):
        return self.visit(node.children[0]) + '.transpose(' + str(node.dim0) + ', ' + str(node.dim1) + ')'

    def visitIrTorchMatmul(self, node):
        return 'torch.matmul(' + self.visit(node.children[0]) + ', ' + self.visit(node.children[1]) + ')'

    def visitIrTorchUnsqueeze(self, node):
        return self.visit(node.children[0]) + '.unsqueeze(' + str(node.index) + ')'

    def visitIrTorchSqueeze(self, node):
        return self.visit(node.children[0]) + '.squeeze(' + str(node.index) + ')'

    def visitIrTorchReshape(self, node):
        return self.visit(node.children[0]) + '.reshape(' + self.visit(node.shape) + ')'

    def visitIrTorchView(self, node):
        return self.visit(node.children[0]) + '.view(' + self.visit(node.shape) + ')'

    def visitIrTorchRepeat(self, node):
        return self.visit(node.children[0]) + '.repeat(' + self.visit(node.repeats) + ')'

    def visitIrTorchExpand(self, node):
        return self.visit(node.children[0]) + '.expand(' + self.visit(node.shape) + ')'

    def visitIrTorchSum(self, node):
        return self.visit(node.children[0]) + '.sum(dim=' + str(node.dim) + ')'

    def visitIrTorchZeros(self, node):
        kwargs = []
        if node.device is not None:
            kwargs.append('device=' + self.visit(node.device))
        if node.dtype is not None:
            kwargs.append('dtype=' + self.visit(node.dtype))
        args = [self.visit(node.size)] + kwargs
        return 'torch.zeros(' + ', '.join(args) + ')'

    def visitIrTorchEye(self, node):
        kwargs = []
        if node.device is not None:
            kwargs.append('device=' + self.visit(node.device))
        if node.dtype is not None:
            kwargs.append('dtype=' + self.visit(node.dtype))
        args = [self.visit(node.size)] + kwargs
        return 'torch.eye(' + ', '.join(args) + ')'

    def visitIrTorchFloat(self, node):
        return self.visit(node.children[0]) + '.float()'

    def visitIrTorchDiagEmbed(self, node):
        return 'torch.diag_embed(' + self.visit(node.children[0]) + ')'

    def visitIrTorchStride(self, node):
        return self.visit(node.children[0]) + '.stride()'

    def visitIrTorchAsStrided(self, node):
        return (
            'torch.as_strided(' + self.visit(node.children[0]) + ', '
            + self.visit(node.size) + ', ' + self.visit(node.stride) + ')'
        )

    def visitIrTensorScatter(self, node):
        # out-of-place: no aliasing for dynamo to reason about, so no graph break
        return (self.visit(node.children[0]) + '.scatter(' + str(node.dim) + ', '
                + node.index + ', ' + self.visit(node.children[1]) + ')')

    def visitIrTorchSlice(self, node):
        return self.visit(node.children[0]) + '[' + self.renderTraceIndex(node.index) + ']'

    def visitIrFConv2d(self, node):
        return (
            'F.conv2d(' + self.visit(node.children[0]) + ', '
            + self.visit(node.children[1]) + ', stride='
            + self.visit(node.stride) + ', padding=' + self.visit(node.padding) + ')'
        )

    def visitIrFConvTranspose2d(self, node):
        kwargs = []
        if node.stride is not None:
            kwargs.append('stride=' + self.visit(node.stride))
        if node.padding is not None:
            kwargs.append('padding=' + self.visit(node.padding))
        if node.output_padding is not None:
            kwargs.append('output_padding=' + self.visit(node.output_padding))
        return (
            'F.conv_transpose2d(' + self.visit(node.children[0]) + ', '
            + self.visit(node.children[1])
            + (', ' + ', '.join(kwargs) if kwargs else '') + ')'
        )

    def visitIrFUnfold(self, node):
        return (
            'F.unfold(' + self.visit(node.children[0]) + ', kernel_size='
            + self.visit(node.kernel_size) + ', padding=' + self.visit(node.padding)
            + ', stride=' + self.visit(node.stride) + ')'
        )

    def visitIrFFold(self, node):
        padding = ', padding=' + self.visit(node.padding) if node.padding is not None else ''
        return (
            'F.fold(' + self.visit(node.children[0]) + ', output_size='
            + self.visit(node.output_size) + ', kernel_size=' + self.visit(node.kernel_size)
            + ', stride=' + self.visit(node.stride) + padding + ')'
        )

    def visitIrTorchEinsum(self, node):
        operands = ', '.join(self.visit(c) for c in node.children)
        return 'torch.einsum(' + repr(node.equation) + ', ' + operands + ')'

    def visitIrAssignToView(self, node):
        view_expr = self.visit(node.children[0])
        index_expr = self.renderTraceIndex(node.index)
        value_expr = self.visit(node.children[1])
        if not inductor_mode.get_flag():
            self.write(view_expr + '[' + index_expr + '] = ' + value_expr)
            return
        # index_expr only references torch/module-level globals, never a local
        # of the calling method, so it's safe to inline in the module-level helper.
        self._method_has_view_write = True
        helper_name = '_view_write_' + str(len(self.view_write_helpers))
        self.view_write_helpers.append(
            '@torch.compiler.disable\n'
            'def ' + helper_name + '(view, value):\n'
            '\tview[' + index_expr + '] = value\n'
            '\treturn view\n'
        )
        self.write(helper_name + '(' + view_expr + ', ' + value_expr + ')')
    
    def visitIrEmptyList(self, node):
        return '[]'

    def visitType(self, node):
        return node.__name__
    
    def visitFloat(self, node):
        if node == float('inf'):
            return "float('inf')"
        if node == float('-inf'):
            return "float('-inf')"
        return str(node)
    
    def visitInt(self, node):
        return str(node)
    
    def visitIrAppendList(self, node):
        return self.visit(node.children[0]) + '+ [' + self.visit(node.children[1]) + ']'
    

    def visitIrListExtract(self, node):
        return '(' + self.visit(node.children[0]) + ')[' + self.visit(node.children[1]) + ']'
    
    def visitIrBlockExtract(self, node):
        return self.visit(node.children[0]) + '.blocks[' + self.visit(node.children[1]) + ']'

    def visitIrBlockCopy(self, node):
        return self.visit(node.children[0]) + '.copy()'
    
    def visitIrGetSparseTensorBlocks(self, node):
        the_sparse_tensor = self.visit(node.children[0])
        return the_sparse_tensor + '.blocks'

    def visitIrGetAbsElemSparseDKey(self, node):
        # the_abs_elem_sparse = self.visit(node.children[0])
        key = node.key
        # return the_abs_elem_sparse + f'.d[{key}]'
        return f'abs_elem.d[\'{key}\']'
    
    def visitIrGetPolyExpSparseConst(self, node):
        the_pes = self.visit(node.children[0])
        return the_pes + '.const'

    def visitIrGetPolyExpSparseMat(self, node):
        the_pes = self.visit(node.children[0])
        return the_pes + '.mat'

    def visitIrGetSymExpSparseConst(self, node):
        the_ses = self.visit(node.children[0])
        return the_ses + '.const'

    def visitIrGetSymExpSparseMat(self, node):
        the_ses = self.visit(node.children[0])
        return the_ses + '.mat'

    def visitIrGetKthLayerNetworkParam(self, node):
        return f'abs_elem.network[{node.layer_index}].{node.param}'

    def visitIrDenseBlock(self, node):
        self.used_block_classes.add(('DenseBlock', node.sparse_block_type))
        return (SPARSE_TIER[node.sparse_block_type] + 'DenseBlock('
                + self.visit(node.children[0]) + ', ' + self._const(node.total_shape) + ', '
                + str(node.batch_size) + ')')

    def visitIrKernelBlock(self, node):
        self.used_block_classes.add(('KernelBlock', node.sparse_block_type))
        return (SPARSE_TIER[node.sparse_block_type] + 'KernelBlock('
                + self.visit(node.children[0]) + ', ' + self._const(node.total_shape) + ', '
                + str(node.ix) + ', ' + str(node.iy) + ', '
                + str(node.ox) + ', ' + str(node.oy) + ', '
                + str(node.sx) + ', ' + str(node.sy) + ', '
                + str(node.px) + ', ' + str(node.py) + ', '
                + str(node.kx) + ', ' + str(node.ky) + ', '
                + str(node.num_channels) + ', ' + str(node.num_kernels) + ')')

    def get_operator_func(self, name: str):
        if not isinstance(name, str):
            name = name.__name__
        OP_MAP = {
            "add": 'operator.add',
            "sub": 'operator.sub',
            "eq": 'operator.eq',
            "ne": 'operator.ne',
            "ge": 'operator.ge',
            "gt": 'operator.gt',
            "le": 'operator.le',
            "lt": 'operator.lt',
            "or_": 'operator.or_',
            "and_": 'operator.and_',
            "mul": 'operator.mul',
            "truediv": 'operator.truediv',
            "floordiv": 'operator.floordiv',
            "mod": 'operator.mod',
            "pow": 'operator.pow',
        }

        try:
            return OP_MAP[name]
        except KeyError:
            raise ValueError(f"Unsupported operator: {name}, {type(name)}")


    def visitIrBlockBinaryOp(self, node):
        return self.visit(node.children[0]) + '.binary(' + self.visit(node.children[1]) + ', ' + self.get_operator_func(node.op) + ')'

    def visitIrBlockWhereBlock(self, node):
        return 'sp_where_block(' + self.visit(node.children[0]) + ', ' + self.visit(node.children[1]) + ', ' + self.visit(node.children[2]) + ')'

    def visitIrBlockUnaryOp(self, node):
        op = node.op
        if op == '-':
            op_str = 'operator.neg'
        elif op == 'not':
            op_str = 'operator.not_'
        elif op == 'sigma':
            op_str = "'sigma'"
        else:
            raise Exception('OP NOT IDENTIFIED', op)
        return self.visit(node.children[0]) + '.unary(' + op_str + ')'
    
    def visitIrGetSubBlockCustomRange(self, node):
        return self.visit(node.children[0]) + '.get_sub_block_custom_range(' + self.visit(node.start_index) + ', ' + self.visit(node.end_index) + ', ' + self.visit(node.block_id) + ', ' + str(node.tensor) + ')'

    def visitTorchTensor(self, node):
        return self._const('torch.tensor(' + str(node.tolist()) + ')')

    def visitIrVar(self, node):
        if node.name == 'sym_size':
            return 'SymExpSparse.count'
        return node.name
    
    def visitIrEpsilon(self, node):
        # num = self.visit(node.num)
        shape = '['
        for i in range(len(node.irMetadata)):
            for j in range(len(node.irMetadata[i].shape)):
                shape += self.visit(node.irMetadata[i].shape[j]) + ","
        shape += ']'
        shape = self._const('torch.tensor(' + shape + ')')
        if node.inside_while:
            return 'get_new_eps(abs_elem.network, ' + shape + ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = True, while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
        return 'get_new_eps(abs_elem.network, ' + shape + ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = False, while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)

    def visitIrNewEps(self, node):
        [matIr, constIr] = node.children
        return 'SymExpSparse(abs_elem.network, ' + self.visit(matIr) + ', ' + self.visit(constIr) + ')'
    
    def visitIrPhi(self, node):
        s = 'phi(['
        for i in range(len(node.children)):
            s += self.visit(node.children[i])
            if i != len(node.children)-1:
                s += ', '
        s += '])'
        return s
    
    def visitIrConvertBoolToFloat(self, node):
        if reuse_mode.get_flag():
            return '('+self.visit(node.children[0])+').float()'
        return 'convert_to_float(' + self.visit(node.children[0]) + ')'

    def visitIrRepeat(self, node):
        repeat_dims = ''
        for i in range(1, len(node.children)):
            repeat_dims += self.visit(node.children[i])
            if i<len(node.children)-1:
                repeat_dims += ', '
        repeat_dims = self._const('torch.tensor([' + repeat_dims + '])')
        if node.inside_while:
            ret = 'repeat(' + self.visit(node.children[0]) + ', ' + repeat_dims + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
        else:
            ret = 'repeat(' + self.visit(node.children[0]) + ', ' + repeat_dims + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)
        return ret

    def visitIrAddDimension(self, node):
        [inputIr] = node.children
        size = 0
        for i in range(len(node.irMetadata)-1):
            for j in range(len(node.irMetadata[i].broadcast)):
                size += 1
        size += len(inputIr.irMetadata[-1].shape)
        indices = []
        for i in range(len(node.irMetadata[-1].shape) - len(inputIr.irMetadata[-1].shape)):
            indices.append(str(size))
            size += 1
        if len(indices) == 0:
            return self.visit(inputIr)
        if node.inside_while:
            kw_suffix = (
                'layer_index = layer_index, '
                'counter = ' + str(node.ttb_counter) + ', inside_while = True, '
                'while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)'
            )
        else:
            kw_suffix = (
                'layer_index = layer_index, '
                'counter = ' + str(node.ttb_counter) + ', inside_while = False, '
                'while_number = ' + str(node.while_number) + ')'
            )
        ret = '(' + self.visit(inputIr) + ')'
        for dim in indices:
            ret = ret + '.unsqueeze(' + dim + ', ' + kw_suffix
        return ret
    
    def visitIrRemoveDimension(self, node):
        [inputIr] = node.children
        if node.inside_while:
            ret = '(' + self.visit(inputIr) + ').squeeze(' + str(node.numDim) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)'
        else:
            ret = '(' + self.visit(inputIr) + ').squeeze(' + str(node.numDim) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')'
        return ret

    def visitIrAddDimensionConst(self, node):
        assert(isinstance(node, IrAddDimensionConst))
        inputIr = node.children[0]
        size = len(node.children)-1
        repeat_dims = ''
        for i in range(1, len(node.children)):
            repeat_dims += self.visit(node.children[i])
            if i<len(node.children)-1:
                repeat_dims += ', '
        if inputIr.irMetadata[-1].isConst:
            if node.inside_while:
                trace = ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = True, while_number = ' + str(node.while_number) + ', while_iteration=while_iteration'
            else:
                trace = ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = False, while_number = ' + str(node.while_number)
            return 'add_dimension_const(' + str(self.visit(inputIr)) + ', ' + self._const('torch.tensor([' + repeat_dims + '])') + trace + ')'
        ret = str(self.visit(inputIr))
        for i in range(size):
            ret += '.unsqueeze(' + str(i) + ')'
        ret += '.repeat(' + self._const('torch.tensor([' + repeat_dims + '])') + ')'
        return ret
    
    def visitIrBinaryOp(self, node):
        op_name = None 
        flag = False
        if node.op == 'max':
            op_name = 'cf_max'
            flag = True
        elif node.op == 'min':
            op_name = 'cf_min'
            flag = True
        elif node.op == '+':
            op_name = 'operator.add'
        elif node.op == '-':
            op_name = 'operator.sub'
        elif node.op == '<=':
            op_name = 'operator.le'
        elif node.op == '<':
            op_name = 'operator.lt'
        elif node.op == '>=':
            op_name = 'operator.ge'
        elif node.op == '>':
            op_name = 'operator.gt'
        elif node.op == '==':
            op_name = 'operator.eq'
        elif node.op == '!=':
            op_name = 'operator.ne'
        elif node.op == 'and':
            op_name = 'operator.and_'
        elif node.op == 'or':
            op_name = 'operator.or_'
        else:
            raise Exception('OP NOT IDENTIFIED', node.op)
        
        [lhsIr, rhsIr] = node.children
        if flag:
            if node.inside_while:
                return op_name + '(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=True, while_number=' + str(node.while_number) + ', while_iteration=while_iteration)'
            return op_name + '(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=False, while_number=' + str(node.while_number) + ')'
        else:
            if node.inside_while:
                return 'binary(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + op_name + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
            

            return 'binary(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + op_name + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)
    
    def visitIrUnaryOp(self, node):
        op_name = None 
        flag = False
        if node.op == '-':
            op_name = 'operator.neg'
        elif node.op == 'not':
            op_name = 'operator.not_'
        elif node.op == 'sigma':
            op_name = f"'sigma'"
        elif node.op == 'any':
            op_name = 'any'
            flag = True
        elif node.op == 'all':
            op_name = 'all'
            flag = True
        elif node.op == 'get_dims':
            op_name = 'get_dims'
            flag = True
        elif node.op == 'get_shape_1':
            op_name = 'get_shape_1'
            flag = True
        elif node.op == 'get_shape_0':
            op_name = 'get_shape_0'
            flag = True
        else:
            raise Exception('OP NOT IDENTIFIED', node.op)
        
        [inputIr] = node.children
        if flag and node.op in ('get_shape_1', 'get_shape_0'):
            return op_name + '(' + self.visit(inputIr) + ')'
        elif flag:
            if node.inside_while:
                return f'{op_name}({self.visit(inputIr)}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=True, while_number={node.while_number}, while_iteration=while_iteration)'
            return f'{op_name}({self.visit(inputIr)}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=False, while_number={node.while_number})'
        else:
            if node.inside_while:
                return 'unary(' + self.visit(inputIr) + ', ' + op_name + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=True, while_number=' + str(node.while_number) + ', while_iteration=while_iteration)'
            return 'unary(' + self.visit(inputIr) + ', ' + op_name + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=False, while_number=' + str(node.while_number) + ')'
        
    def visitIrSimpleUnary(self, node):
        op = node.op
        if isinstance(op, (IrVar, IrLambda)):
            return '(' + self.visit(op) + ')(' + self.visit(node.children[0]) + ')'
        if op == '-':
            op_str = 'operator.neg'
        elif op == 'not':
            op_str = 'operator.not_'
        elif op == 'sigma':
            return 'torch.sigmoid(' + self.visit(node.children[0]) + ')'
        else:
            raise Exception('OP NOT IDENTIFIED', op)
        return op_str + '(' + self.visit(node.children[0]) + ')'

    def visitIrLambda(self, node):
        if node.op in ('add', 'mul', 'and_', 'or_'):
            return 'lambda x: x'
        if node.op == 'sub':
            return 'lambda x: x.unary(operator.neg)'
        raise Exception('OP NOT IDENTIFIED', node.op)

    def visitIrSimpleBinary(self, node):
        [lhsIr, rhsIr] = node.children
        lhs = self.visit(lhsIr)
        rhs = self.visit(rhsIr)
        return self.get_operator_func(node.op) + '(' + lhs + ', ' + rhs + ')'

    def visitIrTorchWhere(self, node):
        return (
            'torch.where(' +
            self.visit(node.children[0]) + ', ' +
            self.visit(node.children[1]) + ', ' +
            self.visit(node.children[2]) +
            ')'
        )
    
    def visitIrTensorOnes(self, node):
        # Was defaulting to CPU unconditionally (no device field was ever
        # recorded), silently mismatching every GPU tensor built elsewhere.
        if isinstance(node.total_size, str):
            return 'torch.ones(*' + node.total_size + ', device=device_mode.get_device())'
        return 'torch.ones(*' + str(node.total_size.tolist()) + ', device=device_mode.get_device())'

    def visitTensorRepeat(self, node):
        return 'torch.repeat(' + self.visit(node.children[0]) + ', *' + node.repeat_dims + ')'

    def visitIrTensorRepeat(self, node):
        return self.visitTensorRepeat(node)
    
    def visitTensorClamp(self, node):
        if node.min_true:
            return 'torch.clamp(' + self.visit(node.children[0]) + ', min=' + str(node.const) + ')'
        else:
            return 'torch.clamp(' + self.visit(node.children[0]) + ', max=' + str(node.const) + ')'

    def visitIrTensorClamp(self, node):
        return self.visitTensorClamp(node)

    def visitIrBlockClamp(self, node):
        return self.visit(node.children[0]) + '.clamp(' + str(node.const) + ', min_true=' + str(node.min_true) + ')'

    def visitIrBlockSqueeze(self, node):
        return self.visit(node.children[0]) + '.squeeze(' + str(node.index) + ')'



    def visitIrGetDefaultStop(self, node):
        repeat_dims = ''
        for i in range(1, len(node.children)):
            repeat_dims += self.visit(node.children[i])
            if i<len(node.children)-1:
                repeat_dims += ', '
        if node.inside_while:
            return f'get_default_stop([{repeat_dims}], abs_elem, batch_size, curr_size, poly_size, layer_index=layer_index, counter={node.ttb_counter}, inside_while=True, while_number={node.while_number}, while_iteration=while_iteration)'
        return f'get_default_stop([{repeat_dims}], abs_elem, batch_size, curr_size, poly_size, layer_index=layer_index, counter={node.ttb_counter}, inside_while=False, while_number={node.while_number})'
    
    def visitIrGetPriorityLList(self, node):
        if node.inside_while:
            return f'get_max_priority({self.visit(node.children[0])}, {self.visit(node.children[1])}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=True, while_number={node.while_number}, while_iteration=while_iteration)'
        return f'get_max_priority({self.visit(node.children[0])}, {self.visit(node.children[1])}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=False, while_number={node.while_number})'
    
    # def visitIrGetPolyexpStop(self, node):
    #     return 'filter_trav_exp_stop(' + self.visit(node.children[0]) + ', ' + self.visit(node.children[1]) + ')'
    
    # def visitIrGetPolyexpNotStop(self, node):
    #     return 'filter_trav_exp_not_stop(' + self.visit(node.children[0]) + ', ' + self.visit(node.children[1]) + ')'
    
    def visitIrGetPolyexpStop(self, node):
        trav = self.visit(node.children[0])
        stop = self.visit(node.children[1])
        if node.inside_while:
            return f'filter_trav_exp_stop({trav}, {stop}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=True, while_number={node.while_number}, while_iteration=while_iteration)'
        return f'filter_trav_exp_stop({trav}, {stop}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=False, while_number={node.while_number})'

    def visitIrGetPolyexpNotStop(self, node):
        trav = self.visit(node.children[0])
        stop = self.visit(node.children[1])
        if node.inside_while:
            return f'filter_trav_exp_not_stop({trav}, {stop}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=True, while_number={node.while_number}, while_iteration=while_iteration)'
        return f'filter_trav_exp_not_stop({trav}, {stop}, layer_index=layer_index, counter={node.ttb_counter}, inside_while=False, while_number={node.while_number})'

    def visitIrPolyExpMat(self, node):
        return self.visit(node.children[0]) + '.mat'

    def visitIrPolyExpNotStopFloat(self, node):
        if reuse_mode.get_flag():
            return '('+self.visit(node.children[0]) + '.unary(operator.not_)).float()'
        return 'convert_to_float(' + self.visit(node.children[0]) + '.unary(operator.not_))'

    def visitIrBlockPolyexpStop(self, node):
        recv = self.visit(node.children[0])
        return (self.polyexp_cls + '(' + recv + '.network, ' + self.visit(node.children[1])
                + ', ' + recv + '.const)')

    def visitIrBlockPolyexpNotStop(self, node):
        recv = self.visit(node.children[0])
        return (self.polyexp_cls + '(' + recv + '.network, ' + self.visit(node.children[1])
                + ', ' + self.visit(node.children[2]) + ')')

    def visitIrBlockAny(self, node):
        return self.visit(node.children[0]) + '.any()'

    def visitIrBlockAll(self, node):
        return self.visit(node.children[0]) + '.all()'

    def visitIrBlockGetDims(self, node):
        return self.visit(node.children[0]) + '.dims'
    
    def visitIrConvertToTensor(self, node):
        repeat_dims = ''
        for i in range(1, len(node.children)):
            repeat_dims += self.visit(node.children[i])
            if i<len(node.children)-1:
                repeat_dims += ', '
        return 'convert_to_tensor(' + self.visit(node.children[0]) + ', [' + repeat_dims +  '])'

    def visitIrMult(self, node):
        op_name = None 
        if node.op == '*':
            op_name = 'operator.mul'
        elif node.op == '/':
            op_name = 'operator.truediv'
        else:
            op_name = node.op
            raise Exception('OP NOT IDENTIFIED', node.op)
        
        [lhsIr, rhsIr] = node.children
        # node.ttb_counter = self.counter
        # self.counter += 1
        # return 'binary' + '(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + op_name + ')'
        if node.inside_while:
            return 'binary(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + op_name + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
        return 'binary(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + op_name + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)
    
    def visitIrInnerProduct(self, node):
        op_name = 'inner_prod'
        
        [lhsIr, rhsIr] = node.children
        if node.inside_while:
            return op_name + '(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
        return op_name + '(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)
    
    def visitIrBlockInnerProduct(self, node):
        if node.type == 'equal_dims':
            return self.visit(node.children[0]) + '.matmul_equal_dims(' + self.visit(node.children[1])+ ')'
        elif node.type == 'unequal_dims':
            return self.visit(node.children[0]) + '.matmul_unequal_dims(' + self.visit(node.children[1])+ ')'
        else:
            raise Exception('OP NOT IDENTIFIED', node.type)

    def visitIrDot(self, node):
        [lhsIr, rhsIr] = node.children
        dot_args = (
            ', layer_index = layer_index, '
            + 'counter = ' + str(node.ttb_counter)
            + ', inside_while = ' + ('True' if node.inside_while else 'False')
            + ', while_number = ' + str(node.while_number)
        )
        if node.inside_while:
            dot_args += ', while_iteration = while_iteration'
        if lhsIr.irMetadata[-1].type == 'Neuron':
            return self.visit(lhsIr) + '.dot(' + self.visit(rhsIr) + ', abs_elem.get_poly_size()' + dot_args + ", mats_input = 'rhs')"
        elif rhsIr.irMetadata[-1].type == 'Neuron':
            return self.visit(rhsIr) + '.dot(' + self.visit(lhsIr) + ', abs_elem.get_poly_size()' + dot_args + ", mats_input = 'lhs')"
        elif lhsIr.irMetadata[-1].type == 'Float':
            if node.inside_while:
                return 'inner_prod(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
            return 'inner_prod(' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)
        else:
            raise Exception('NOT IMPLEMENTED')

    def visitIrTernary(self, node):
        [condIr, lhsIr, rhsIr] = node.children
        return 'where(' + self.visit(condIr) + ', ' + self.visit(lhsIr) + ', ' + self.visit(rhsIr) + ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = ' + ('True' if node.inside_while else 'False') + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)

    def visitIrClamp(self, node):
        [inputIr, const] = node.children
        min_true = node.min_true 
        if node.inside_while:
            return 'clamp(' + self.visit(inputIr) + ', ' + str(const) + ', ' + str(min_true) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = True' + ', while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)' + self._ttb_comment(node)
        return 'clamp(' + self.visit(inputIr) + ', ' + str(const) + ', ' + str(min_true) + ', ' + 'layer_index = layer_index, ' + 'counter = ' + str(node.ttb_counter) + ', inside_while = False' + ', while_number = ' + str(node.while_number) + ')' + self._ttb_comment(node)

    def visitIrCombineToPoly(self, node):
        [coeffIr, constIr, rows] = node.children
        cols = 'poly_size'
        return self.polyexp_cls + '(abs_elem.network, ' + self.visit(coeffIr) + ' , ' + self.visit(constIr) + ')'

    def visitIrCombineToSym(self, node):
        [coeffIr, constIr, rows] = node.children
        cols = 'SymExpSparse.count'
        rows = self.visit(rows)
        return 'SymExpSparse(abs_elem.network,' + self.visit(coeffIr) + ', ' + self.visit(constIr) + ')'


    def visitIrExtractPolyCoeff(self, node):
        [inputIr] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        return self.visit(inputIr) + '.get_mat(abs_elem' \
            + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=' + str(node.inside_while) + ', while_number=' + str(node.while_number) + ', while_iteration=' + while_iteration + ')'
    
    def visitIrExtractSymCoeff(self, node):
        [inputIr] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        return self.visit(inputIr) + '.get_mat(SymExpSparse.count' \
            + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=' + str(node.inside_while) + ', while_number=' + str(node.while_number) + ', while_iteration=' + while_iteration + ')'

    def visitIrExtractPolyConst(self, node, ):
        [inputIr] = node.children
        if reuse_mode:
            return self.visit(inputIr) + '.const'
        return self.visit(inputIr) + '.get_const()'
    
    def visitIrExtractSymConst(self, node):
        [inputIr] = node.children
        if reuse_mode:
            return self.visit(inputIr) + '.const'
        return self.visit(inputIr) + '.get_const()'

    def visitIrConvertNeuronToPoly(self, node):
        [inputIr] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        return self.visit(inputIr) + '.convert_to_poly(abs_elem' \
            + ', layer_index=layer_index, counter=' + str(node.ttb_counter) \
            + ', inside_while=' + str(node.inside_while) \
            + ', while_number=' + str(node.while_number) \
            + ', while_iteration=' + while_iteration + ')'
    
    def visitIrConcatStitch(self, node):
        [prev1Ir, prev2Ir] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        return (f"concat_stitch_2d(abs_elem, '{node.key}', '{node.source}', "
                f"{self.visit(prev1Ir)}, {self.visit(prev2Ir)}, layer_index=layer_index, "
                f"counter={node.ttb_counter}, inside_while={node.inside_while}, "
                f"while_number={node.while_number}, while_iteration={while_iteration})")

    def visitIrConcatStitchMat(self, node):
        [prev1Ir, prev2Ir] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        return (f"concat_stitch_mat(abs_elem, '{node.key}', "
                f"{self.visit(prev1Ir)}, {self.visit(prev2Ir)}, layer_index=layer_index, "
                f"counter={node.ttb_counter}, inside_while={node.inside_while}, "
                f"while_number={node.while_number}, while_iteration={while_iteration})")

    def visitIrConvertConstToPoly(self, node):
        [inputIr, rows] = node.children
        cols = 'poly_size'
        return self.polyexp_cls + '(abs_elem.network, 0.0, ' + self.visit(inputIr) + ')'
        
    def visitIrConvertConstToSym(self, node):
        [inputIr, rows] = node.children
        cols = 'SymExpSparse.count'
        rows = self.visit(rows)
        return 'SymExpSparse(abs_elem.network,' + 'None, ' + self.visit(inputIr) + ')'
    
    def visitIrExpandSymExp(self, node):
        [inputIr] = node.children
        if not reuse_mode.get_flag():
            return self.visit(inputIr) + '.expand_symexp_mat(SymExpSparse.count)'
        var_name = self._hoist_if_complex(self.visit(inputIr))
        # Rebind rather than mutate in place: total_size may alias a hoisted
        # constant shared by other blocks/tensors, so writing through it would
        # corrupt every other user of that constant.
        self.write(var_name + '.total_size = torch.cat([' + var_name + '.total_size[:-1], torch.tensor([SymExpSparse.count], dtype=torch.int64)])')
        return var_name

    def visitIrAccess(self, node):
        [lhsIr] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        if not node.isMetadata:
            return 'abs_elem.get_elem(\'' + node.elem + '\', ' + self.visit(lhsIr) \
                + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=' + str(node.inside_while) + ', while_number=' + str(node.while_number) + ', while_iteration=' + while_iteration + ')'
        else:
            return self.visit(lhsIr) + '.get_metadata(\'' + node.elem + '\', batch_size' \
                + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=' + str(node.inside_while) + ', while_number=' + str(node.while_number) + ', while_iteration=' + while_iteration + ')'
        
    def visitIrReduce(self, node):
        [inputIr] = node.children
        size = node.reduce_dim
        if node.inside_while:
            return '(' + self.visit(inputIr) + ').sum(' + str(size) + ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = True, while_number = ' + str(node.while_number) + ', while_iteration=while_iteration)'
        return '(' + self.visit(inputIr) + ').sum(' + str(size) + ', layer_index = layer_index, counter = ' + str(node.ttb_counter) + ', inside_while = False, while_number = ' + str(node.while_number) + ')'

    def visitIrMapCoeff(self, node):
        [inputIr] = node.children
        while_iteration = 'while_iteration' if node.inside_while else 'None'
        if inputIr.irMetadata[-1].type == 'PolyExp':    
            return self.visit(inputIr) + '.get_mat(abs_elem' \
                + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=' + str(node.inside_while) + ', while_number=' + str(node.while_number) + ', while_iteration=' + while_iteration + ')'
        return self.visit(inputIr) + '.get_mat(SymExpSparse.count' \
                + ', layer_index=layer_index, counter=' + str(node.ttb_counter) + ', inside_while=' + str(node.inside_while) + ', while_number=' + str(node.while_number) + ', while_iteration=' + while_iteration + ')'

    def visitIrMapNeuron(self, node):
        if node.dims:
            return 'Llist(abs_elem.network, [1]*(' + self.visit(node.children[0]) + '), None, None,' + "abs_elem.live_layers)"
        else:
            return 'Llist(abs_elem.network, [1]*(' + self.visit(node.children[0]) + '.mat.dims-1), None, None,' + "abs_elem.live_layers)"

    def visitIrSymbolic(self, node):
        return node.name
    
    def visitIrFlow(self, node):
        self.indent += 1
        if sroa_build():
            self.write('res = flow(*explode_inputs(abs_elem, batch_size))')
            self.write('if not inductor_mode.get_flag():')
            self.write('    print("Peak memory usage:", torch.cuda.max_memory_allocated() / 1024**2, "MB")')
            self.write('return res')
            self.indent -= 1
            return
        if fused_build():
            # The unrolled flow() returns the final abstract shape; densify it here.
            self.write('abs_shape = flow(abs_elem, batch_size)')
            self.write('res = get_dense_inlined(abs_shape[0]), get_dense_inlined(abs_shape[1])')
            self.write('if not inductor_mode.get_flag():')
            self.write('    print("Peak memory usage:", torch.cuda.max_memory_allocated() / 1024**2, "MB")')
            self.write('return res')
            self.indent -= 1
            return
        self.write('flow = Flow(abs_elem, ' + str(node.transformer) + '(), network, print_intermediate_results, no_sparsity)')
        self.write('res = flow.flow()')
        self.write('if not inductor_mode.get_flag():')
        self.write('    print("Peak memory usage:", torch.cuda.max_memory_allocated() / 1024**2, "MB")')
        self.write('return res')
        self.indent -= 1

    def visitIrObjectLookup(self, node):
        if node.object_name == "block":
            return self.visit(node.children[0]) + ".block"
        raise Exception("NOT IMPLEMENTED")

    def visitIrBlockCreateSimilar(self, node):
        return (
            self.visit(node.children[0]) +
            ".create_similar(" +
            self.visit(node.children[1]) +
            ")"
        )

    def visitIrSetBlockTotalShapeLastDim(self, node):
        block_var = self._hoist_if_complex(self.visit(node.children[0]))
        value = self.visit(node.children[1])
        # Rebind rather than mutate in place -- see visitIrExpandSymExp.
        self.write(block_var + ".total_shape = torch.cat([" + block_var + ".total_shape[:-1], torch.tensor([" + value + "], dtype=torch.int64)])")

    def visitIrAssignToBlock(self, node):
        block_var = self.visit(node.children[0])
        value = self.visit(node.children[1])
        self.write(block_var + ".block = " + value)

    def visitIrBlockGetSubBlockCustomRange(self, node):
        return (
            self.visit(node.children[0]) +
            ".get_sub_block_custom_range(" +
            self.visit(node.start_index) + ", " +
            self.visit(node.end_index) + ", " +
            self.visit(node.block_start_index) +
            ")"
        )
