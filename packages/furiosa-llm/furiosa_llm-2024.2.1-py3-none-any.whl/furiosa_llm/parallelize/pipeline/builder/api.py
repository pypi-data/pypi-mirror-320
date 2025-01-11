import copy
import gc
from itertools import chain
import json
import logging
import operator
import os
from pathlib import Path
from time import time
from typing import Any, Dict, List, Mapping, MutableMapping, Optional, Sequence, Tuple, Type, Union

from furiosa_torch_ext.torch_ext import SIDE_EFFECT_OPS
import ray
import torch
from torch._subclasses import FakeTensorMode
from torch.fx import Graph, GraphModule, Node
from torch.fx.node import _side_effectful_functions
from torch.utils._pytree import tree_flatten, tree_map_only
from transformers import PretrainedConfig

from furiosa_llm.parallelize.block_slicer import (
    get_block_slicing_edges,
    get_blockwise_sliced_color_map,
)
from furiosa_llm.parallelize.compiler_config import CompilerConfigContext
from furiosa_llm.parallelize.export.graphmodule import deserialize_gm
from furiosa_llm.parallelize.export.tensor import (
    ParamfileFormat,
    ParamFileInfo,
    get_saved_param_names,
    save_tensors,
    write_without_concurrency_issue,
)
from furiosa_llm.parallelize.hash import get_env_independent_hash, hash_example_inputs, hash_model
from furiosa_llm.parallelize.model_creation_info import ModelCreationInfo
from furiosa_llm.parallelize.model_rewriter.api import ModelRewriter
from furiosa_llm.parallelize.model_rewriter.ops import custom_ops  # noqa: F401
from furiosa_llm.parallelize.mppp.api import Mppp
from furiosa_llm.parallelize.mppp.config import Device, MpppConfig
from furiosa_llm.parallelize.node_meta import (
    QParamKind,
    get_color,
    get_original_name,
    get_qparam_kind,
    has_original_name,
    set_color,
    set_original_name,
    set_to_be_embedded,
    set_unsharded_tensor_meta,
)
from furiosa_llm.parallelize.pipeline.builder.arg_types import InputSampleWithMeta
from furiosa_llm.parallelize.pipeline.builder.converter import (
    ADDITIONAL_PARAM_FILE_ID,
    DEFAULT_PARAM_FILE_ID,
    GraphModuleConverter,
    _tensor_exists_in_file,
)
from furiosa_llm.parallelize.pipeline.builder.transform import (
    OpInfo,
    append_op_to_the_graph,
    replace_paged_attention_index_ops_with_furiosa_sparse_index,
)
from furiosa_llm.parallelize.pipeline.builder.utils import get_constant_tensors_with_original_name
from furiosa_llm.parallelize.pipeline.types import (
    CompSuperTask,
    MetadataTensor,
    MetadataTensorSlice,
    ParamInfo,
    Pipeline,
    SuperTaskKind,
    TensorGenInfo,
)
from furiosa_llm.parallelize.trace import get_aten_graph_with_original_names
from furiosa_llm.parallelize.utils import (
    get_cache_path_if_exists,
    get_fake_mode,
    get_original_model_type,
    is_aten_op,
    is_custom_op,
    zip_equal,
)

logger = logging.getLogger(__file__)


def _get_example_input(
    supertask: CompSuperTask,
    pipeline: Pipeline,
    fake_mode: FakeTensorMode,
) -> Tuple[torch.Tensor, ...]:
    with fake_mode:
        return tuple(
            torch.zeros(
                pipeline.tensors[input_].shape,
                dtype=pipeline.tensors[input_].dtype.to_torch_dtype(),
            )
            for input_ in supertask.inputs
        )


def _info_log_for_ray(msg: str):
    logger.info(f"[furiosa-llm] {msg}")


# IMPORTANT: Compiler config generation part part in this function must be kept same as `GraphModuleConverter._get_data_blob_id`.
def _compile_supertasks_in_pipeline(
    pipeline: Pipeline,
    target_ir: str,
    # current context: model_type, beam_size, phase, bucket
    compiler_config_context: CompilerConfigContext,
    serialize_compiled_graphs: bool = False,
) -> None:
    fake_mode = FakeTensorMode(allow_non_fake_inputs=True)

    compiled_blobs = set()
    # Dump an intermediate artifact (e.g., DFG, ir graphs, dot graphs) for debugging purpose
    dump_path = os.getenv("FURIOSA_COMPILE_DUMP_PATH")

    for supertask_id, supertask in pipeline.supertasks.items():
        if not isinstance(supertask, CompSuperTask):
            continue
        if supertask.kind != SuperTaskKind.FX:
            raise NotImplementedError("Supertask kind other than FX cannot be compiled now")
        if supertask.data_blob is not None:
            if supertask.data_blob in compiled_blobs:
                # already compiled
                supertask.kind = SuperTaskKind.from_str(target_ir)
                continue
            blob = pipeline.blobs[supertask.data_blob]
        else:
            assert isinstance(supertask.data, str)
            blob = supertask.data

        gm = deserialize_gm(blob)
        example_input = _get_example_input(supertask, pipeline, fake_mode)
        target_npu = GraphModuleConverter.get_target_npu_from_device(
            pipeline.devices[supertask.device]
        )

        _info_log_for_ray(
            f"Compiling pipeline {pipeline.name}, supertask {supertask_id} for {target_npu}."
        )

        compiler_config = None
        compiler_config_context = copy.deepcopy(compiler_config_context)
        num_pe = pipeline.devices[supertask.device].num_pe
        compiler_config_context.num_pe = num_pe

        block_type = pipeline.get_block_type_from_supertask_id(supertask_id)
        num_pe = pipeline.devices[supertask.device].num_pe
        logger.info("Block type: %s", block_type)

        compiler_config_context = copy.deepcopy(compiler_config_context)
        compiler_config_context.block_type = block_type
        compiler_config_context.num_pe = num_pe

        compiler_config = compiler_config_context.load_config()
        logger.info(f"Using compiler config {compiler_config}")

        compiled = GraphModuleConverter.compile_gm(
            gm,
            example_input,
            target_npu,
            target_ir,
            compiler_config,
            supertask.data_blob,
            dump_path,
        )
        _info_log_for_ray(
            f"Finished compiling pipeline {pipeline.name}, supertask {supertask_id} for {target_npu}."
        )

        if serialize_compiled_graphs:
            compiled = compiled.serialize()

        if supertask.data_blob is not None:
            # replace data_blobs
            pipeline.blobs[supertask.data_blob] = compiled
            compiled_blobs.add(supertask.data_blob)
        else:
            supertask.data = compiled
        supertask.kind = SuperTaskKind.from_str(target_ir)


def _get_sliced_torch_where_get_attr_nodes(gm: GraphModule) -> Tuple[Node, ...]:
    """Find get_attr nodes if it's used as ``torch.ops.aten.where``'s condition tensor (first input tensor) after a slice opertion."""

    cache = set()
    to_be_embedded = set()
    for node in gm.graph.nodes:
        if not (node.op == "call_function" and node.target == torch.ops.aten.where.self):
            continue

        queue: List[Tuple[Node, bool]] = [(node.args[0], False)]

        while queue:
            node, found_slice = queue.pop()
            if node.op == "get_attr" and found_slice:
                to_be_embedded.add(node)
                continue
            flattened_args, _ = tree_flatten((node.args, node.kwargs))
            for arg in flattened_args:
                if not isinstance(arg, Node) or arg in cache:
                    continue
                cache.add(arg)
                queue.append((arg, found_slice or arg.target == torch.ops.aten.slice.Tensor))
    return tuple(to_be_embedded)


def _get_zero_point_for_dpe_qparam_nodes(gm: GraphModule) -> Tuple[Node, ...]:
    """Get zero point qparam get_attr nodes running on DPE."""
    zp_for_dpe_nodes = tuple(
        node
        for node in gm.graph.nodes
        if node.op == "get_attr" and get_qparam_kind(node) == QParamKind.ZERO_POINT_FOR_DPE
    )

    for node in zp_for_dpe_nodes:
        actual_tensor = getattr(gm, node.target)
        # This assumption is not valid for fp8 models.
        if actual_tensor.dim() != 0 and tuple(actual_tensor.shape) != (1,):
            raise RuntimeError(
                f"Non-sclar dpe zero-point qparam {node.name} found, all dpe zero-point qparams should be sclar tensors for compilation."
            )
        if actual_tensor.count_nonzero() > 0:
            # TODO: remove this after compiler issue is fixed.
            logger.warning(
                f"non-zero dpe zero-point qparam found: {node.name}, this may cause inefficient compilation."
            )

    return zp_for_dpe_nodes


def _mark_constants_to_be_embedded(gm: GraphModule) -> None:
    """Mark some constants (get_attr nodes) to be embedded in FX graph as it is."""
    for node in _get_sliced_torch_where_get_attr_nodes(gm) + _get_zero_point_for_dpe_qparam_nodes(
        gm
    ):
        set_to_be_embedded(node)


def _get_commit_id() -> str:
    import furiosa_llm

    if furiosa_llm.__version__:
        return furiosa_llm.__version__.hash
    else:
        import git  # type: ignore

        repo = git.Repo(Path(__file__).parent, search_parent_directories=True)
        return repo.head.object.hexsha


def _add_block_id_info(
    original_model_type: Type,
    aten_gm: GraphModule,
    num_blocks_per_supertask: int,
) -> None:
    """Add block id info for nodes in ``aten_gm``."""
    slicing_edges = get_block_slicing_edges(aten_gm, original_model_type)

    # Get block id map for nodes. Nodes with same block id belongs to same block.
    get_blockwise_sliced_color_map(aten_gm, slicing_edges, mark_color_to_meta=True)

    # Cahnge block ids according to `num_blocks_per_supertask``.
    for node in aten_gm.graph.nodes:
        colors = get_color(node)
        if colors is None:
            continue
        new_colors = [color // num_blocks_per_supertask for color in colors]
        set_color(node, new_colors)


ANONYMOUS_CONSTANT_NAME_PREFIX = "ANONYMOUS_CONSTANT_"


def _add_original_name_to_anonymous_get_attr_nodes(gm: GraphModule) -> None:
    existing_original_names = set(
        get_original_name(node) for node in gm.graph.nodes if has_original_name(node)
    )
    cnt = 0
    for node in gm.graph.nodes:
        if node.op != "get_attr" or has_original_name(node):
            continue
        constant_name = f"{ANONYMOUS_CONSTANT_NAME_PREFIX}{cnt}"
        cnt += 1
        assert (
            constant_name not in existing_original_names
        ), f"constant name {constant_name} already exists in the model."
        set_original_name(node, constant_name)


class PipelineBuilder:
    model: Union[torch.nn.Module, ModelCreationInfo]
    model_config: Optional[PretrainedConfig]

    def __init__(
        self,
        model: Union[torch.nn.Module, ModelCreationInfo],
        model_config: Optional[PretrainedConfig],
        tmp_dir: os.PathLike,
        is_beam_search_kv_cache_sharing_model: bool,
    ):
        self.model = model
        self.model_config = model_config
        self.tmp_dir = Path(tmp_dir)
        self.is_beam_search_kv_cache_sharing_model = is_beam_search_kv_cache_sharing_model

    def __gen_pipepline_hash(
        self,
        example_args: Sequence[Any],
        example_kwargs: Dict[str, Any],
        mppp_config: MpppConfig,
        param_info: ParamFileInfo,
        comp_supertask_kind: SuperTaskKind,
        use_blockwise_compile: bool,
        do_decompositions_for_model_rewrite: bool,
        padding_block_idx: Optional[int],
        sparse_select_version: str,
        embed_all_constants_into_graph: bool,
        num_blocks_per_supertask: int,
    ) -> str:
        if isinstance(self.model, ModelCreationInfo):
            original_model_type = self.model.metadata.get_optimized_cls()
            model_config = self.model.metadata.config
            qformat_qparam_path = self.model.get_qparam_qformat_path()
            quantization_config = self.model.metadata.quantization_config
            seed = self.model.seed
            is_random_weight_model = self.model.random_weight_model
        else:
            # TODO
            raise NotImplementedError("Don't support pipeline hashing for non-metadata models.")

        saved_param_names = get_saved_param_names(param_info)
        saved_param_names.sort()

        to_be_hashed = (
            _get_commit_id(),
            hash_model(
                original_model_type,
                model_config,
                quantization_config,
                qformat_qparam_path,
                model_config.name_or_path,
                seed,
                is_random_weight_model,
            ),
            hash_example_inputs(example_args, example_kwargs),
            mppp_config.to_json(),
            json.dumps(saved_param_names),
            str(comp_supertask_kind),
            str(use_blockwise_compile),
            str(do_decompositions_for_model_rewrite),
            str(padding_block_idx),
            str(num_blocks_per_supertask),
            str(embed_all_constants_into_graph),
            sparse_select_version,
        )

        return get_env_independent_hash(to_be_hashed)

    @staticmethod
    def __is_aten_graph(graph: Graph) -> bool:
        return all(
            node.op in ("placeholder", "get_attr", "output")
            or (
                node.op == "call_function"
                and (
                    is_aten_op(node.target)
                    or is_custom_op(node.target)
                    or node.target == operator.getitem
                )
            )
            for node in graph.nodes
        )

    @staticmethod
    def __add_unsharded_tensor_meta(
        graph: Graph,
    ):
        # store unsharde shape info for placeholder/output nodes.
        for node in graph.nodes:
            if node.op == "placeholder":
                set_unsharded_tensor_meta(node, node.meta["tensor_meta"])
            elif node.op == "output":
                set_unsharded_tensor_meta(
                    node, tuple(arg.meta["tensor_meta"] for arg in node.args[0])
                )

    def __additional_param_file_path(self, pipeline_name: str) -> Path:
        return self.tmp_dir / f"add_const_file-{pipeline_name}.safetensors"

    def save_additional_params(
        self,
        example_args: Sequence[Any],
        example_kwargs: Dict[str, Any],
        file_path: os.PathLike,
        target_params: Sequence[str],
        save_format: ParamfileFormat = ParamfileFormat.SAFETENSORS,
        cache_dir: Optional[os.PathLike] = None,
    ) -> None:
        """Save parameters in ``model``, but not in ``excludes`` to ``file_path``."""
        assert not os.path.exists(file_path)

        # Some additional params appear in aten-level, so lower it to aten level.
        aten_gm = get_aten_graph_with_original_names(
            self.model,
            example_args,
            example_kwargs,
            cache_dir=cache_dir,
        )[0]

        _add_original_name_to_anonymous_get_attr_nodes(aten_gm)

        all_tensor_constants = get_constant_tensors_with_original_name(aten_gm)
        constants_to_be_saved = {name: all_tensor_constants[name] for name in target_params}

        # Save additional params to ``file_path`` if exists.
        if constants_to_be_saved:
            save_tensors(constants_to_be_saved, file_path, save_format)

    def __gen_pipeline(
        self,
        pipeline_name: str,
        example_args: Sequence[Any],
        example_kwargs: Dict[str, Any],
        mppp_config: MpppConfig,
        param_file_info: ParamFileInfo,
        export_path: Optional[Path],
        comp_supertask_kind: SuperTaskKind,
        # current context: model_qname, beam_size, phase, bucket
        compiler_config_context: CompilerConfigContext,
        input_names: Optional[Sequence[str]],
        output_names: Optional[Sequence[str]],
        one_supertask_per_device: bool,
        use_blockwise_compile: bool,
        do_decompositions_for_model_rewrite: bool,
        padding_block_idx: Optional[int],
        sparse_select_version: str,
        embed_all_constants_into_graph: bool,
        num_blocks_per_supertask: int,
        add_last_block_slice: bool,
        cache_dir: Optional[os.PathLike],
    ) -> Pipeline:
        if aten_gm := getattr(self, "aten_gm", None):
            pass
        else:
            aten_gm = get_aten_graph_with_original_names(
                self.model,
                example_args,
                example_kwargs,
                input_names=input_names,
                output_names=output_names,
                do_decompositions_for_model_rewrite=do_decompositions_for_model_rewrite,
                cache_dir=cache_dir,
                param_file_info=param_file_info,
            )[0]

        logger.info("Add metadata and rewrite fx graph.")
        start = time()

        # What we want to do is to prevent only side-effect ops with no user from being eliminated by dead code elimination.
        # But union of ``_side_effectful_functions`` and ``SIDE_EFFECT_OPS`` contains only some of those side-effect ops.
        # TODO: Find a way to get a list of all side-effect aten ops.
        for node in aten_gm.graph.nodes:
            if (
                node.op != "output"
                and len(node.users) == 0
                and node.target not in _side_effectful_functions.union(SIDE_EFFECT_OPS)
            ):
                logger.warning(
                    f"Node with no user found, this might means meaningful nodes can disappear during postprocess: {node}"
                )

        assert PipelineBuilder.__is_aten_graph(aten_gm.graph)

        # Add original name for anonymous get_attr nodes, which are not given name by `add_original_name_info` and `add_qparam_info`.
        _add_original_name_to_anonymous_get_attr_nodes(aten_gm)

        # mark some tensor constants (get_attr nodes) to be embedded in FX graph as it is
        # (instead of converting them as placeholders in future stages).
        _mark_constants_to_be_embedded(aten_gm)

        if padding_block_idx is not None:
            replace_paged_attention_index_ops_with_furiosa_sparse_index(
                aten_gm.graph,
                padding_block_idx,
                self.is_beam_search_kv_cache_sharing_model,
                sparse_select_version,
            )

        if add_last_block_slice:
            self._apply_last_block_slice(aten_gm.graph)

        # Get constants that are not saved in given parameter file.
        # This will be passed to PipelineConverter.
        constants_not_in_param_file = get_constant_tensors_with_original_name(
            aten_gm,
        )

        # Exclude already saved ones
        for name in get_saved_param_names(param_file_info):
            constants_not_in_param_file.pop(name, None)

        # Save parameters not in parameter saved file referenced by ``param_file_info`` (e.g., qparam).
        additional_param_file_info = ParamFileInfo(
            str(self.__additional_param_file_path(pipeline_name)), ParamfileFormat.SAFETENSORS
        )

        PipelineBuilder.__add_unsharded_tensor_meta(aten_gm.graph)

        fake_mode = get_fake_mode(chain(aten_gm.parameters(), aten_gm.buffers()))
        fake_args_for_aten_gm = tuple(
            fake_mode.from_tensor(node.meta["val"])
            for node in aten_gm.graph.nodes
            if node.op == "placeholder"
        )

        if use_blockwise_compile:
            if isinstance(self.model, ModelCreationInfo):
                original_model_type = self.model.metadata.get_optimized_cls()
            else:
                assert isinstance(self.model, torch.nn.Module)
                original_model_type = get_original_model_type(self.model)

            # Add block id information for nodes if possible.
            _add_block_id_info(original_model_type, aten_gm, num_blocks_per_supertask)

        model_rewriter = ModelRewriter(aten_gm, mppp_config)

        rewritten_model = model_rewriter.rewrite(fake_args_for_aten_gm)

        logger.info("Adding metadata and rewriting fx graph took %.2f seconds.", time() - start)

        start = time()
        pipeline = GraphModuleConverter(
            rewritten_model,
            mppp_config.devices,
            model_rewriter.get_device_id_map(),
        ).convert(
            pipeline_name,
            param_file_info,
            comp_supertask_kind,
            compiler_config_context,
            one_supertask_per_device,
            additional_param_file_info,
            constants_not_in_param_file,
            use_blockwise_compile,
            embed_all_constants_into_graph,
        )
        logger.info("Converting GraphModule to pipeline took %.2f seconds.", time() - start)

        if export_path is not None:
            write_without_concurrency_issue(pipeline.to_json(), export_path)

        return pipeline

    @staticmethod
    def __replace_original_tensor_names(
        origin: MutableMapping[str, MetadataTensor],
        slices: Mapping[str, MetadataTensorSlice],
        new_names: Sequence[str],
    ) -> bool:
        need_resave = False
        replace_map = {}

        # Find original tensor names that need to be replaced.
        for cur_name, original_tensor_info in tuple(origin.items()):
            new_name = new_names[original_tensor_info.idx]
            if cur_name != new_name:
                origin[new_name] = original_tensor_info
                need_resave = True
                replace_map[cur_name] = new_name

        # Replace original tensor names in tensor slices.
        for tensor_slice_meta in slices.values():
            if tensor_slice_meta.origin in replace_map:
                tensor_slice_meta.origin = replace_map[tensor_slice_meta.origin]
        return need_resave

    def build_pipelines(
        self,
        devices: Sequence[Device],
        mppp: Mppp,
        input_samples_in_metadata_with_name: Sequence[InputSampleWithMeta],
        param_file_path,
        comp_supertask_kind: SuperTaskKind = SuperTaskKind.FX,
        cache_dir: Optional[Path] = None,
        one_supertask_per_device: bool = False,
        use_blockwise_compile: bool = False,
        do_decompositions_for_model_rewrite: bool = False,
        sparse_select_version: str = "v1.5",
        embed_all_constants_into_graph: bool = False,
        num_blocks_per_supertask: int = 1,
        padding_block_idx: Optional[int] = None,
        param_saved_format: str = "safetensors",
        num_pipeline_builder_workers: int = 1,
        num_compile_workers: int = 1,
    ) -> List[Pipeline]:
        input_samples_in_metadata_with_name_copied = copy.copy(input_samples_in_metadata_with_name)
        try:
            ray.init(num_cpus=max([num_pipeline_builder_workers - 1, num_compile_workers - 1]))
            pipelines = self.build_fx_pipelines_in_parallel(
                devices=devices,
                mppp=mppp,
                input_samples_in_metadata_with_name=input_samples_in_metadata_with_name,
                param_file_path=param_file_path,
                cache_dir=cache_dir,
                one_supertask_per_device=one_supertask_per_device,
                use_blockwise_compile=use_blockwise_compile,
                do_decompositions_for_model_rewrite=do_decompositions_for_model_rewrite,
                sparse_select_version=sparse_select_version,
                embed_all_constants_into_graph=embed_all_constants_into_graph,
                num_blocks_per_supertask=num_blocks_per_supertask,
                num_pipeline_builder_workers=num_pipeline_builder_workers,
                padding_block_idx=padding_block_idx,
                param_saved_format=param_saved_format,
            )
            assert all(isinstance(pipeline, Pipeline) for pipeline in pipelines)

            if comp_supertask_kind is SuperTaskKind.FX:
                return pipelines
            else:
                # order should be preserved
                compile_config_contexts = [
                    input_sample.compile_config
                    for input_sample in input_samples_in_metadata_with_name_copied
                ]
                return PipelineBuilder.compile_supertasks_in_parallel(
                    pipelines,
                    compile_config_contexts,
                    comp_supertask_kind.to_ir_kind(),
                    num_compile_workers,
                )
        finally:
            ray.shutdown()

    def build_fx_pipelines_in_parallel(
        self,
        devices: Sequence[Device],
        mppp: Mppp,
        input_samples_in_metadata_with_name: Sequence[InputSampleWithMeta],
        param_file_path,
        cache_dir: Optional[Path] = None,
        one_supertask_per_device: bool = False,
        use_blockwise_compile: bool = False,
        do_decompositions_for_model_rewrite: bool = False,
        sparse_select_version: str = "v1.5",
        embed_all_constants_into_graph: bool = False,
        num_blocks_per_supertask: int = 1,
        num_pipeline_builder_workers: int = 1,
        padding_block_idx: Optional[int] = None,
        param_saved_format: str = "safetensors",
    ) -> List[Pipeline]:  #

        assert num_pipeline_builder_workers > 0

        tasks: List[List[InputSampleWithMeta]] = [
            list() for _ in range(num_pipeline_builder_workers)
        ]
        # split task into remote task and local task
        div, remain = divmod(len(input_samples_in_metadata_with_name), num_pipeline_builder_workers)
        num_tasks = [div] * num_pipeline_builder_workers
        for i in range(remain):
            num_tasks[i] += 1

        input_samples_in_metadata_with_name = list(input_samples_in_metadata_with_name)
        for i, task in enumerate(tasks):
            while len(task) < num_tasks[i]:
                task.append(input_samples_in_metadata_with_name.pop(0))
        assert len(input_samples_in_metadata_with_name) == 0
        assert len(tasks) == num_pipeline_builder_workers
        assert all(len(task) == num_tasks[i] for i, task in enumerate(tasks))

        local_task = tasks[0]  # only on local task
        remote_tasks = tasks[1:] if len(tasks) >= 2 else list()

        other_args = (
            devices,
            param_file_path,
            cache_dir,
            mppp,
            one_supertask_per_device,
            use_blockwise_compile,
            do_decompositions_for_model_rewrite,
            padding_block_idx,
            sparse_select_version,
            embed_all_constants_into_graph,
            num_blocks_per_supertask,
            param_saved_format,
        )
        if num_pipeline_builder_workers == 1:
            ## solely do local run
            pipelines_local = PipelineBuilder.__build_fx_pipelines_aux(
                self, input_samples_in_metadata_with_name=local_task, other_args=other_args
            )
            return pipelines_local

        assert remote_tasks

        ## remote runs
        common_args = ray.put(other_args)
        remote_tasks_to_call = [
            PipelineBuilder.__build_fx_pipelines_with_ray.remote(self, task, common_args)
            for task in remote_tasks
        ]

        pipelines_remote = ray.get(remote_tasks_to_call)
        pipelines_local = PipelineBuilder.__build_fx_pipelines_aux(
            self, input_samples_in_metadata_with_name=local_task, other_args=other_args
        )
        pipelines_remote = [pipeline for pipelines in pipelines_remote for pipeline in pipelines]

        return pipelines_local + pipelines_remote

    @staticmethod
    @ray.remote
    def __build_fx_pipelines_with_ray(
        builder: "PipelineBuilder",
        input_samples_with_name: Sequence[InputSampleWithMeta],
        other_args: Sequence,
    ) -> List[Pipeline]:
        return PipelineBuilder.__build_fx_pipelines_aux(
            builder, input_samples_with_name, other_args
        )

    @staticmethod
    def __build_fx_pipelines_aux(
        builder: "PipelineBuilder",
        input_samples_in_metadata_with_name: Sequence[InputSampleWithMeta],
        other_args: Sequence,
    ) -> List[Pipeline]:
        (
            devices,
            param_file_path,
            cache_dir,
            mppp,
            one_supertask_per_device,
            use_blockwise_compile,
            do_decompositions_for_model_rewrite,
            padding_block_idx,
            sparse_select_version,
            embed_all_constants_into_graph,
            num_blocks_per_supertask,
            param_saved_format,
        ) = other_args

        if param_saved_format == "safetensors":
            param_saved_format_ = ParamfileFormat.SAFETENSORS
        elif param_saved_format == "pt":
            param_saved_format_ = ParamfileFormat.TORCHSAVE
        else:
            raise ValueError(f"Invalid param saved format: {param_saved_format}")

        pipelines = list()

        def tensor_meta_data_to_tensor(tensor_gen_info: TensorGenInfo):
            assert isinstance(tensor_gen_info, TensorGenInfo)
            return torch.zeros(size=tensor_gen_info.shape, dtype=tensor_gen_info.dtype)

        for input_sample in input_samples_in_metadata_with_name:
            example_input_by_tensor_metadata_args = input_sample.args_data
            example_input_by_tensor_metadata_kwargs = input_sample.kwargs_data
            pipeline_name = input_sample.pipeline_name
            compiler_config_context = input_sample.compile_config

            # this example input is assumed to include TensorMetaData,
            # but turn in into fake tensor in here
            with FakeTensorMode(allow_non_fake_inputs=True):
                example_input_in_fake_tensor_args = tree_map_only(
                    TensorGenInfo, tensor_meta_data_to_tensor, example_input_by_tensor_metadata_args
                )
                example_input_in_fake_tensor_kwargs = tree_map_only(
                    TensorGenInfo,
                    tensor_meta_data_to_tensor,
                    example_input_by_tensor_metadata_kwargs,
                )

            _info_log_for_ray(f"Generating pipeline {pipeline_name}")
            pipeline = builder.build(
                pipeline_name,
                devices,
                example_input_in_fake_tensor_args,
                example_input_in_fake_tensor_kwargs,
                mppp,
                ParamFileInfo(os.fspath(param_file_path), param_saved_format_),
                compiler_config_context,
                SuperTaskKind.FX,
                cache_dir=cache_dir,
                one_supertask_per_device=one_supertask_per_device,
                use_blockwise_compile=use_blockwise_compile,
                do_decompositions_for_model_rewrite=do_decompositions_for_model_rewrite,
                padding_block_idx=padding_block_idx,
                sparse_select_version=sparse_select_version,
                embed_all_constants_into_graph=embed_all_constants_into_graph,
                num_blocks_per_supertask=num_blocks_per_supertask,
                add_last_block_slice=input_sample.add_last_block_slice,
            )
            gc.collect()
            pipelines.append(pipeline)
        return pipelines

    @staticmethod
    def compile_supertasks_in_parallel(
        pipelines: Sequence[Pipeline],
        compile_config_contexts: Sequence[CompilerConfigContext],
        target_ir: str,
        num_workers: int,
    ) -> List[Pipeline]:
        assert len(pipelines) == len(compile_config_contexts)

        if num_workers == 1:
            for pipeline, compile_config in zip(pipelines, compile_config_contexts):
                _compile_supertasks_in_pipeline(pipeline, target_ir, compile_config)
            return list(pipelines)
        else:  # do parellel run

            pipelines_with_compile_config = list(zip_equal(compile_config_contexts, pipelines))
            share, remainder = divmod(len(pipelines_with_compile_config), num_workers)
            remote_pipelines_ray_tasks = [
                PipelineBuilder.__compile_supertasks_with_ray.remote(
                    pipelines_with_compile_config[
                        worker_idx * share
                        + min(worker_idx, remainder) : (worker_idx + 1) * share
                        + min(worker_idx + 1, remainder)
                    ],
                    target_ir,
                )
                for worker_idx in range(1, num_workers)
            ]

            local_pipelines = PipelineBuilder.__compile_supertasks_aux(
                pipelines_with_compile_config[: share + min(1, remainder)], target_ir
            )
            remote_pipelines: List[Pipeline] = sum(ray.get(remote_pipelines_ray_tasks), [])

            for pipeline in remote_pipelines:
                for task in pipeline.supertasks.values():
                    if not isinstance(task, CompSuperTask) or task.kind is SuperTaskKind.FX:
                        continue
                    try:
                        from furiosa.native_compiler import CompiledGraph  # type: ignore[import]
                    except ImportError:
                        logger.error("furiosa-native-compiler is required to load EDF format")
                        raise

                    if task.data is not None:
                        if isinstance(task.data, bytes):
                            task.data = CompiledGraph.deserialize(task.data, tag="")
                    else:
                        assert task.data_blob is not None
                        data = pipeline.blobs[task.data_blob]  # type: ignore[attr-defined]
                        if isinstance(data, bytes):
                            pipeline.blobs[task.data_blob] = CompiledGraph.deserialize(  # type: ignore[assignment, arg-type, attr-defined]
                                data, tag=task.data_blob
                            )

            return local_pipelines + remote_pipelines  # type: ignore

    @staticmethod
    def __compile_supertasks_aux(
        pipelines: Sequence[Tuple[CompilerConfigContext, Pipeline]],
        target_ir: str,
        serialize_compiled_graphs: bool = False,
    ) -> List[Pipeline]:
        for compiler_config_context, pipeline in pipelines:
            start = time()
            _info_log_for_ray(f"Compiling supertasks in {pipeline.name}.")
            _compile_supertasks_in_pipeline(
                pipeline,
                target_ir,
                compiler_config_context,
                serialize_compiled_graphs=serialize_compiled_graphs,
            )
            _info_log_for_ray(
                f"Finished compiling supertasks in {pipeline.name}, elapsed: {time() - start:.2f}s."
            )

        return list(map(operator.itemgetter(1), pipelines))

    @staticmethod
    @ray.remote
    def __compile_supertasks_with_ray(
        pipelines: Sequence[Tuple[CompilerConfigContext, Pipeline]], target_ir: str
    ) -> List[Pipeline]:
        return PipelineBuilder.__compile_supertasks_aux(
            pipelines, target_ir, serialize_compiled_graphs=True
        )

    def build(
        self,
        pipeline_name: str,
        devices: Sequence[Device],
        example_args: Sequence[Any],
        example_kwargs: Dict[str, Any],
        mppp_or_mppp_config: Union[MpppConfig, Mppp],
        param_info: ParamFileInfo,
        # current context: model_qname, beam_size, phase, bucket
        compiler_config_context: CompilerConfigContext,
        comp_supertask_kind: SuperTaskKind = SuperTaskKind.FX,
        input_names: Optional[Sequence[str]] = None,
        output_names: Optional[Sequence[str]] = None,
        cache_dir: Optional[Path] = None,
        one_supertask_per_device: bool = False,
        use_blockwise_compile: bool = False,
        do_decompositions_for_model_rewrite: bool = False,
        padding_block_idx: Optional[int] = None,
        sparse_select_version: str = "v1.5",
        embed_all_constants_into_graph: bool = False,
        num_blocks_per_supertask: int = 1,
        add_last_block_slice: bool = False,
    ) -> Pipeline:
        if isinstance(mppp_or_mppp_config, Mppp):
            # Original name information might be needed for mppp config generation (e.g., block slicer).
            self.aten_gm = get_aten_graph_with_original_names(
                self.model,
                example_args,
                example_kwargs,
                input_names=input_names,
                output_names=output_names,
                do_decompositions_for_model_rewrite=do_decompositions_for_model_rewrite,
                cache_dir=cache_dir,
                param_file_info=param_info,
            )[0]
            mppp_config = mppp_or_mppp_config.gen_config(
                self.model,
                self.model_config,
                devices,
                example_args,
                example_kwargs,
                graph_module=self.aten_gm,
            )
        else:
            mppp_config = mppp_or_mppp_config

        # We cache models only if model is `ModelCreationInfo` now.
        # TODO: add caching support for ordinary nn.Module.
        if (
            cache_dir is not None
            and isinstance(self.model, ModelCreationInfo)
            and self.model.is_hashable()
        ):
            # name is not used for hashing because it doesn't affect other fields of pipeline.
            pipeline_hash = self.__gen_pipepline_hash(
                example_args,
                example_kwargs,
                mppp_config,
                param_info,
                comp_supertask_kind,
                use_blockwise_compile,
                do_decompositions_for_model_rewrite,
                padding_block_idx,
                sparse_select_version,
                embed_all_constants_into_graph,
                num_blocks_per_supertask,
            )
            need_resave = False
            need_additional_param_save = False  # whether parameters not in parameter file referenced by ``param_info`` exists.
            additional_params_to_be_saved = []
            additional_param_file_path = self.__additional_param_file_path(pipeline_name)
            export_path = cache_dir / "pipelines" / f"{pipeline_name}-{pipeline_hash}.json"
            os.makedirs(cache_dir / "pipelines", exist_ok=True)

            cached_pipeline_path = get_cache_path_if_exists(pipeline_hash, "json", cache_dir)

            if cached_pipeline_path:
                # cached pipeline exists.
                cached_pipeline = Pipeline.load(cached_pipeline_path)
                if cached_pipeline.name != pipeline_name:
                    need_resave = True
                    cached_pipeline.name = pipeline_name

                if input_names is not None:
                    need_resave &= PipelineBuilder.__replace_original_tensor_names(
                        cached_pipeline.metadata.tensors.inputs,
                        cached_pipeline.metadata.tensor_slices.inputs,
                        input_names,
                    )
                if output_names is not None:
                    need_resave &= PipelineBuilder.__replace_original_tensor_names(
                        cached_pipeline.metadata.tensors.outputs,
                        cached_pipeline.metadata.tensor_slices.outputs,
                        output_names,
                    )

                for tensor_info in cached_pipeline.tensors.values():
                    if not isinstance(tensor_info, ParamInfo):
                        continue
                    cached_param_file_info = cached_pipeline.param_files[
                        tensor_info.value.param_file
                    ]
                    if cached_param_file_info != param_info:
                        # Different param file is used.
                        need_resave = True
                        if _tensor_exists_in_file(tensor_info.value.name, param_info):
                            # check given param file has same param names as
                            # param file used for cached pipeline
                            tensor_info.value.param_file = DEFAULT_PARAM_FILE_ID
                        else:
                            # This param doesn't exist in given param file. Add this to  ``additional_params_to_be_saved``.
                            tensor_info.value.param_file = ADDITIONAL_PARAM_FILE_ID
                            need_additional_param_save = True
                            additional_params_to_be_saved.append(tensor_info.value.name)

                cached_pipeline.param_files[DEFAULT_PARAM_FILE_ID] = param_info
                save_format = ParamfileFormat.SAFETENSORS
                cached_pipeline.param_files[ADDITIONAL_PARAM_FILE_ID] = ParamFileInfo(
                    os.fspath(additional_param_file_path), save_format
                )

                if need_additional_param_save:
                    self.save_additional_params(
                        example_args,
                        example_kwargs,
                        additional_param_file_path,
                        additional_params_to_be_saved,
                        save_format,
                        cache_dir=cache_dir,
                    )

                # if name, param info or input/output names is different from cached one,
                # reexport the pipeline.
                if need_resave:
                    write_without_concurrency_issue(cached_pipeline.to_json(), export_path)

                return cached_pipeline
        else:
            # don't cache
            export_path = None

        # Don't cache if comp_supertask_kind != "fx" because other formats
        # cannot be serialized properly.
        # FIXME: cache other formats after fixing issues.
        if comp_supertask_kind != "fx":
            export_path = None

        return self.__gen_pipeline(
            pipeline_name,
            example_args,
            example_kwargs,
            mppp_config,
            param_info,
            export_path,
            comp_supertask_kind,
            compiler_config_context,
            input_names,
            output_names,
            one_supertask_per_device,
            use_blockwise_compile,
            do_decompositions_for_model_rewrite,
            padding_block_idx,
            sparse_select_version,
            embed_all_constants_into_graph,
            num_blocks_per_supertask,
            add_last_block_slice,
            cache_dir=cache_dir,
        )

    def _apply_last_block_slice(self, graph: Graph):
        logger.info("Add slice op at the end of the graph.")

        if not isinstance(self.model, ModelCreationInfo):
            raise NotImplementedError("Prefill last block slice is not supported for this model.")
        slice_dim = self.model.metadata.seq_dim_in_logits

        # Find logits node
        output_node = next(iter(reversed(graph.nodes)))
        assert output_node.op == "output"

        output_tensor_nodes = output_node.args[0]

        if len(output_tensor_nodes) == 1:
            logits_node = output_tensor_nodes[0]
        else:
            original_names = get_original_name(output_node)
            assert isinstance(original_names, tuple)
            assert len(output_tensor_nodes) == len(original_names)
            logits_index = original_names.index("logits")
            logits_node = output_tensor_nodes[logits_index]

        append_op_to_the_graph(
            graph, OpInfo(torch.ops.aten.slice.Tensor, (slice_dim, -1)), logits_node
        )
