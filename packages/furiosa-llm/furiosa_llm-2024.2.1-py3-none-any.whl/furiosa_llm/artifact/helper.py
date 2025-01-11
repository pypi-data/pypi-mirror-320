from collections import deque
import copy
from itertools import islice
import logging
import os
from pathlib import Path
from typing import Dict, List, Optional, Sequence, Set, Tuple, Type, Union

from torch._subclasses import FakeTensorMode
import torch.distributed._tensor.ops.common_rules
from torch.utils._pytree import tree_map_only
from transformers import PretrainedConfig, PreTrainedModel

from furiosa_llm.parallelize.mppp.config import DeviceId
from furiosa_llm.parallelize.pipeline.builder.arg_types import InputSampleWithMeta
from furiosa_llm.parallelize.pipeline.types import (
    CommSuperTask,
    CompSuperTask,
    Device,
    InOutputSuperTask,
    MetaData,
    MetadataTensorSlice,
    MetadataTensorSlices,
    NameAfterMakeFx,
    ParamInfo,
    SuperTask,
    SuperTaskId,
    SuperTaskKind,
    TensorInfo,
)

from ..models import ModelMetadata
from ..models.config_types import (
    Bucket,
    BucketConfig,
    KvCacheSharingAcrossBeamsConfig,
    LLMBackend,
    ManualBucketConfig,
    MinimalBucketConfig,
    PagedAttentionConfig,
)
from ..models.utils import generate_input_sample
from ..parallelize.compiler_config import CompilerConfigContext, PipelineMode
from ..parallelize.export.tensor import save_model
from ..parallelize.model_creation_info import ModelCreationInfo
from ..parallelize.mppp.api import Mppp
from ..parallelize.pipeline import Pipeline
from ..parallelize.pipeline.builder import PipelineBuilder
from ..parallelize.pipeline.types import TensorGenInfo

logger = logging.getLogger(__name__)

# TODO: do we need to relax this assumption?
_CHUNKED_PREFILL_BUCKETS_BATCH_SIZE = 1


def generate_input_samples(
    model_config: PretrainedConfig,
    buckets: Sequence[Bucket],
    kv_cache_dtype: Optional[torch.dtype],
    paged_attention_config: Optional[PagedAttentionConfig],
    kv_cache_shaing_across_beams_config: Optional[KvCacheSharingAcrossBeamsConfig],
    is_packed_optimized: bool,
    compact_causal_mask_for_bert: bool,
    use_causal_mask_for_prefill: bool,
    need_args_for_speculative_decoding: bool,
    is_quantized: bool,
    go_through_mcp: bool,
    is_sliced_model: bool,
    prefill_pipeline_mode: PipelineMode,
    decode_pipeline_mode: PipelineMode,
    original_model_type: Type,
    compiler_config_context: CompilerConfigContext,
    add_prefill_last_block_slice: bool,
) -> Sequence[InputSampleWithMeta]:

    def extract_tensor_info(tensor: torch.Tensor) -> TensorGenInfo:
        return TensorGenInfo(shape=tensor.shape, dtype=tensor.dtype)

    with FakeTensorMode(allow_non_fake_inputs=True):
        input_samples_with_name = list()
        for bucket in buckets:
            input_sample_data = generate_input_sample(
                model_config,
                bucket,
                kv_cache_dtype,
                paged_attention_config,
                kv_cache_shaing_across_beams_config,
                is_packed_optimized,
                compact_causal_mask_for_bert,
                use_causal_mask_for_prefill,
                need_args_for_speculative_decoding,
                go_through_mcp,
                is_sliced_model,
            )
            input_sample_data = tree_map_only(torch.Tensor, extract_tensor_info, input_sample_data)
            model_name = (
                f"Quantized_{original_model_type.__module__}.{original_model_type.__name__}"
                if is_quantized
                else f"{original_model_type.__module__}.{original_model_type.__name__}"
            )
            # Please reflect the implementation of PipelineName in furiosa-llm-tests/src/e2e_base.rs
            # TODO: save needed information in Pipeline's metadata, instead of saving it in pipeline name.
            pipeline_name = f"{model_name}-kv{bucket.kv_cache_size}-b{bucket.batch_size}-attn{bucket.attention_size}"
            compiler_config_context = copy.deepcopy(compiler_config_context)

            if bucket.is_prefill:
                compiler_config_context.phase = prefill_pipeline_mode
            elif bucket.is_decode:
                compiler_config_context.phase = decode_pipeline_mode
            else:
                # FIXME: change this to proper phase config
                compiler_config_context.phase = PipelineMode.UNKNOWN
            compiler_config_context.bucket = bucket

            input_samples_with_name.append(
                InputSampleWithMeta(
                    args_data=[],  # assumed LLM models have kwargs only
                    kwargs_data=input_sample_data,
                    pipeline_name=pipeline_name,
                    compile_config=compiler_config_context,
                    add_last_block_slice=add_prefill_last_block_slice and bucket.is_prefill,
                )
            )
        return input_samples_with_name


def build_pipelines(
    model: ModelCreationInfo,
    config: PretrainedConfig,
    buckets: Sequence[Bucket],
    devices: Sequence[Device],
    param_file_path: Optional[os.PathLike],
    cache_dir: Optional[Path],
    backend: LLMBackend,
    mppp: Mppp,
    comp_supertask_kind: SuperTaskKind,
    one_supertask_per_device: bool,
    use_blockwise_compile: bool,
    do_decompositions_for_model_rewrite: bool,
    kv_cache_dtype: Optional[torch.dtype],
    paged_attention_config: Optional[PagedAttentionConfig],
    sparse_select_version: str,
    kv_cache_shaing_across_beams_config: Optional[KvCacheSharingAcrossBeamsConfig],
    tmp_dir: Optional[os.PathLike],
    model_metadata: ModelMetadata,
    # current context: model_qname, beam_size
    compiler_config_context: CompilerConfigContext,
    num_pipeline_builder_workers: int,
    num_compile_workers: int,
    embed_all_constants_into_graph: bool,
    num_blocks_per_supertask: int,
    add_prefill_last_block_slice: bool,
    is_generative_model: bool,
    param_saved_format: str = "safetensors",
    **kwargs,
) -> List[Pipeline]:
    if backend.is_parallelism_supported():
        prefill_pipeline_mode = (
            PipelineMode.LLM_PREFILL if is_generative_model else PipelineMode.UNKNOWN
        )
        decode_pipeline_mode = (
            PipelineMode.LLM_DECODE if is_generative_model else PipelineMode.UNKNOWN
        )

        assert param_file_path is not None, "parameter saved file must be given when using pipeline"
        assert tmp_dir is not None

        # do pre-compile first, and generate a pipelines with fx.graph supertask
        is_beam_search_kv_cache_sharing_model = (
            model_metadata.is_beam_search_kv_cache_sharing_model()
        )

        pipeline_builder = PipelineBuilder(
            model,
            config,
            tmp_dir,
            is_beam_search_kv_cache_sharing_model=is_beam_search_kv_cache_sharing_model,
        )
        is_packed_optimized = model_metadata.optimize_options.optimize_packed
        compact_causal_mask_for_bert = model_metadata.is_compact_causal_mask_for_bert()
        use_causal_mask_for_prefill = model_metadata.optimize_options.causal_mask_free_decoding
        need_args_for_speculative_decoding = model_metadata.supports_speculative_decoding
        is_quantized = model_metadata.is_quantized

        if isinstance(model, PreTrainedModel):
            original_model_type = model.original_type
        else:
            assert isinstance(model, ModelCreationInfo)
            original_model_type = model.metadata.get_optimized_cls()

        input_samples_in_metadata_with_name = generate_input_samples(
            model_config=config,
            buckets=buckets,
            kv_cache_dtype=kv_cache_dtype,
            paged_attention_config=paged_attention_config,
            kv_cache_shaing_across_beams_config=kv_cache_shaing_across_beams_config,
            is_packed_optimized=is_packed_optimized,
            compact_causal_mask_for_bert=compact_causal_mask_for_bert,
            use_causal_mask_for_prefill=use_causal_mask_for_prefill,
            need_args_for_speculative_decoding=need_args_for_speculative_decoding,
            is_quantized=is_quantized,
            go_through_mcp=model.metadata.need_quant_artifacts,
            is_sliced_model=model.metadata.optimize_options.calculate_logit_only_for_last_token,
            prefill_pipeline_mode=prefill_pipeline_mode,
            decode_pipeline_mode=decode_pipeline_mode,
            original_model_type=original_model_type,
            compiler_config_context=compiler_config_context,
            add_prefill_last_block_slice=add_prefill_last_block_slice,
        )

        pipelines = pipeline_builder.build_pipelines(
            devices=devices,
            mppp=mppp,
            input_samples_in_metadata_with_name=input_samples_in_metadata_with_name,
            param_file_path=param_file_path,
            comp_supertask_kind=comp_supertask_kind,
            cache_dir=cache_dir,
            one_supertask_per_device=one_supertask_per_device,
            use_blockwise_compile=use_blockwise_compile,
            do_decompositions_for_model_rewrite=do_decompositions_for_model_rewrite,
            sparse_select_version=sparse_select_version,
            embed_all_constants_into_graph=embed_all_constants_into_graph,
            num_blocks_per_supertask=num_blocks_per_supertask,
            padding_block_idx=(
                paged_attention_config.padding_block_idx if paged_attention_config else None
            ),
            param_saved_format=param_saved_format,
            num_pipeline_builder_workers=num_pipeline_builder_workers,
            num_compile_workers=num_compile_workers,
        )

        return pipelines
    else:
        raise ValueError(f"unsupported backend: {backend}")


def _get_buckets_for_chunked_prefill(
    max_seq_len: int,
    chunk_size: int,
) -> List[Bucket]:
    assert chunk_size <= max_seq_len

    share, remainder = divmod(max_seq_len, chunk_size)
    buckets = []

    # XXX: We only consider buckets with batch 1 if chunked prefill is used.
    for i in range(1, share + 1):
        buckets.append(
            Bucket(
                _CHUNKED_PREFILL_BUCKETS_BATCH_SIZE,
                i * chunk_size,
                (i - 1) * chunk_size,
            )
        )
    if remainder:
        buckets.append(
            Bucket(
                _CHUNKED_PREFILL_BUCKETS_BATCH_SIZE,
                max_seq_len,
                share * chunk_size,
            )
        )
    return buckets


def get_buckets(
    bucket_config: BucketConfig,
    is_generative_model: bool,
    max_seq_len_to_capture: int,
    num_speculative_tokens: Optional[int],
    prefill_chunk_size: Optional[int],
) -> Tuple[List[Bucket], List[Bucket], List[Bucket]]:
    if isinstance(bucket_config, MinimalBucketConfig):
        assert bucket_config.max_seq_len == max_seq_len_to_capture
        # If chunked prefill is used, original prefill buckets are not used.
        if not prefill_chunk_size:
            prefill_buckets = [Bucket.prefill(1, max_seq_len_to_capture)]
        decode_buckets = [Bucket.decode(1, max_seq_len_to_capture)] if is_generative_model else []
    elif isinstance(bucket_config, ManualBucketConfig):
        if not prefill_chunk_size:
            prefill_buckets = [Bucket.prefill(*bucket) for bucket in bucket_config.prefill_buckets]
        else:
            # If chunked prefill is used, original prefill buckets are not used.
            if bucket_config.prefill_buckets:
                logger.warning(
                    "`prefill_chunk_size` is given. All given manual prefill buckets is ignored."
                )
        if is_generative_model:
            # FIXME: This is a temporary workaround to support empty decode bucket case,
            # just for getting fx graphs using `LLM.get_splitted_gms` without creating `NativeLLMEngine`.
            if bucket_config.decode_buckets is None:
                raise ValueError("decode_buckets must be given for generative models.")
            decode_buckets = [Bucket.decode(*bucket) for bucket in bucket_config.decode_buckets]
        else:
            if bucket_config.decode_buckets:
                logger.warning(
                    "decode_buckets will be ignored because the model is not a generative model."
                )
            decode_buckets = []
    else:
        raise ValueError(f"Invalid bucket config: {bucket_config}")

    other_buckets: List[Bucket] = []

    # Generate buckets for speculative decoding if needed.
    if num_speculative_tokens is not None:
        if num_speculative_tokens == 0:
            raise ValueError("`num_speculative_tokens` must be larger than 0.")
        other_buckets.extend(
            Bucket(
                bucket.batch_size,
                bucket.attention_size,
                # NOTE: Why input_ids length become (num_speculative_tokens + 1) instead of num_speculative_tokens?
                # Whenever target model verifies draft model's sugges tokens, it generates exactly one bonus token regardless
                # of how many suggestion tokens are actually accepted. And at the time of next verification, this bonus token
                # (from previous verification) should be given as an input_ids (not kv cache!) because there is no kv cache for this bonus token.
                # So input_ids length for each verification should be num_speculative_tokens + 1 (for bonus token).
                bucket.attention_size - (num_speculative_tokens + 1),
            )
            for bucket in decode_buckets
        )

    if prefill_chunk_size:
        prefill_buckets = []
        if prefill_chunk_size > max_seq_len_to_capture:
            raise ValueError(
                "`prefill_chunk_size` should be smaller than `max_seq_len_to_capture`."
            )
        buckets_for_chunked_prefill = _get_buckets_for_chunked_prefill(
            max_seq_len_to_capture, prefill_chunk_size
        )
        for bucket in buckets_for_chunked_prefill:
            if bucket.is_prefill:
                # Expect only one prefill bucket exists.
                assert not prefill_buckets
                prefill_buckets.append(bucket)
            else:
                other_buckets.append(bucket)

    return prefill_buckets, decode_buckets, other_buckets


def instantiate_and_save_model(
    model_metadata: ModelMetadata,
    use_random_weight: bool,
    qformat_path: Optional[os.PathLike],
    qparam_path: Optional[os.PathLike],
    path: os.PathLike,
    quant_ckpt_file_path: Optional[os.PathLike] = None,
) -> None:
    if use_random_weight:
        if quant_ckpt_file_path:
            raise ValueError(
                "`quant_ckpt_file_path` will be ignored when random weight model is used."
            )
        model_ = model_metadata.random_weight_model(
            qformat_path=qformat_path,
            qparam_path=qparam_path,
        )
    else:
        model_ = model_metadata.pretrained_model(
            qformat_path=qformat_path,
            qparam_path=qparam_path,
            quant_ckpt_file_path=quant_ckpt_file_path,
        )
    save_model(model_, path)


def _is_match_in_inoutputs(
    sp_task: Union[CommSuperTask, CompSuperTask],
    succ_sp_task: Union[CommSuperTask, CompSuperTask],
) -> bool:
    """
    Determine whether two supertasks will execute sequentially by verifying if the outputs of `sp_task` are passed as inputs to `succ_sp_task`.
    If so, we record outputs of `sp_task` to mark them as inter-supertask input arg for `succ_sp_task`.
    """
    if isinstance(sp_task, CompSuperTask) and isinstance(succ_sp_task, CompSuperTask):
        return set(sp_task.outputs).issubset(set(succ_sp_task.inputs)) and sp_task != succ_sp_task
    elif isinstance(sp_task, CompSuperTask) and isinstance(succ_sp_task, CommSuperTask):
        return sp_task.outputs == succ_sp_task.inputs and succ_sp_task.kind is SuperTaskKind.SEND
    elif isinstance(sp_task, CommSuperTask):
        if sp_task.kind is SuperTaskKind.RECV:
            return isinstance(succ_sp_task, CompSuperTask) and set(sp_task.outputs).issubset(
                set(succ_sp_task.inputs)
            )
        elif sp_task.kind is SuperTaskKind.SEND:
            return (
                isinstance(succ_sp_task, CommSuperTask)
                and succ_sp_task.kind is SuperTaskKind.RECV
                and succ_sp_task.group == sp_task.group
            )
        else:
            raise ValueError(f"Invalid CommSuperTask {sp_task} is encountered.")
    else:
        raise ValueError(f"Unexepcted Supertask {sp_task} and {succ_sp_task}")


def _get_ordered_supertasks(
    pipeline: Pipeline,
) -> List[Tuple[Union[CompSuperTask, CommSuperTask], Set[NameAfterMakeFx]]]:
    """
    Returns an ordered sequence of Comp/Comm Supertasks in execution order using a topological-sort style algorithm.
    Dependencies between two supertasks are determined by matching output and input args between tasks.
    """
    ordered_super_tasks = list()
    inter_supertask_args = set(
        x
        for supertask in pipeline.supertasks.values()
        for x in supertask.outputs
        if not isinstance(supertask, InOutputSuperTask)
    )

    # Derive a starting CompSuperTask
    # Starting CompSuperTask <> inputs are consisted of arguments excluding inter-supertask args(e.g., `recv`, `submod_d0_c1`) or param/tensor constants
    starting_comp_super_tasks: Sequence[
        Tuple[Union[CommSuperTask, CompSuperTask], Set[NameAfterMakeFx]]
    ] = [
        (sp_task, set())
        for sp_task in pipeline.supertasks.values()
        if isinstance(sp_task, CompSuperTask)
        and not set(sp_task.inputs).intersection(inter_supertask_args)
    ]

    # following must be guranteed if input `pipeline` is well-formed
    assert starting_comp_super_tasks

    queue_nodes = deque(starting_comp_super_tasks)

    while queue_nodes:
        visited = queue_nodes.popleft()
        ordered_super_tasks.append(visited)
        for sp_task in pipeline.supertasks.values():
            if not isinstance(sp_task, (CompSuperTask, CommSuperTask)):
                continue
            is_matched = _is_match_in_inoutputs(visited[0], sp_task)
            if is_matched:
                queue_nodes.append((sp_task, set(visited[0].outputs)))
    assert len(ordered_super_tasks) == len(
        [
            supertask
            for supertask in pipeline.supertasks.values()
            if not isinstance(supertask, InOutputSuperTask)
        ]
    )
    return ordered_super_tasks


def override_pp_size_on_pipeline(
    old_pipeline: Pipeline,
    devices: Sequence[Sequence[Device]],
    pipeline_parallel_size: Union[int, None],
    num_blocks_per_pp_stage: Union[Sequence[int], None],
) -> Pipeline:
    """
    Returns a new Pipeline that satisfies the pipeline parallelism specified by either pipeline_parallel_size or num_blocks_per_pp_stage,
    by overriding `old_pipeline`. While the generated pipeline is guaranteed to be semantically equivalent to old_pipeline, the input and output argument names may differ.
    """
    assert not (pipeline_parallel_size and num_blocks_per_pp_stage)
    num_of_comp_supertask = len(
        [
            supertask
            for supertask in old_pipeline.supertasks.values()
            if isinstance(supertask, CompSuperTask)
        ]
    )
    if num_blocks_per_pp_stage and sum(num_blocks_per_pp_stage) != num_of_comp_supertask:
        raise ValueError(
            "Sum of `num_blocks_per_pp_stage` must be equal to number of CompSuperTasks within the pipeline."
        )

    # If only `pipeline_parallel_size` is provided, do pp-overriding in even distribution of transformer blocks
    if pipeline_parallel_size and (not num_blocks_per_pp_stage):
        if num_of_comp_supertask % pipeline_parallel_size != 0:
            raise ValueError(
                "For even distribution of transformer blocks over pipeline stages,"
                + "the number of CompSuperTasks within the pipeline must be divisible by `pipeline_parallel_size`."
            )
        num_blocks_per_pp_stage = [
            num_of_comp_supertask // pipeline_parallel_size
        ] * pipeline_parallel_size

    assert num_blocks_per_pp_stage

    if len(devices) != len(num_blocks_per_pp_stage):
        raise ValueError(
            f"Number of devices must be equal to pipeline parallelism size {len(num_blocks_per_pp_stage)}"
        )

    # Returns an overriding pipeline that aligns with the pipeline parallelism specified by num_blocks_per_pp_stage.
    ordered_super_tasks = _get_ordered_supertasks(old_pipeline)

    # Types are specified in `List` type due to later usage of .append()
    ordered_comp_supertasks: List[Tuple[CompSuperTask, Set[NameAfterMakeFx]]] = list()
    for idx, spt in enumerate(ordered_super_tasks):
        if isinstance(spt[0], CompSuperTask):
            if idx != (len(ordered_super_tasks) - 1) and len(spt[0].outputs) > 1:
                raise NotImplementedError(
                    "Currently, pp overriding only supports pipelines of intermediate CompSuperTasks with single output."
                )
            ordered_comp_supertasks.append(spt)  # type: ignore[arg-type]

    assert ordered_comp_supertasks

    new_devices = dict()
    for device_id, device in enumerate(devices):
        if len(device) != 1:
            raise NotImplementedError(
                "Currently, we do not support pipeline parallelism overriding over artifacts with inter-chip tensor parallelism."
            )
        new_devices[DeviceId(str(device_id))] = device[0]

    old_input_tensor_slices: Dict[NameAfterMakeFx, MetadataTensorSlice] = (
        old_pipeline.metadata.tensor_slices.inputs
    )

    old_pipeline_constant_args: Set[NameAfterMakeFx] = {
        name for name, info in old_pipeline.tensors.items() if isinstance(info, ParamInfo)
    }

    updated_pipeline_tensors: Dict[NameAfterMakeFx, Union[TensorInfo, ParamInfo]] = {
        constant_arg_name: old_pipeline.tensors[constant_arg_name]
        for constant_arg_name in old_pipeline_constant_args  # preserve the constant args
    }
    updated_pipeline_meta_tensorslices_input: Dict[NameAfterMakeFx, MetadataTensorSlice] = dict()
    in_iter = iter(ordered_comp_supertasks)
    slices_of_comps_per_device = [list(islice(in_iter, 0, i)) for i in num_blocks_per_pp_stage]

    updated_non_inoutput_spt = list()

    # Typed as `List` for the consistency with the field type defined in `SuperTask`
    outputs_of_non_inoutput_spt_lastly_added: List[NameAfterMakeFx] = list()
    group_id_cnt = 0

    def get_metadata_tensorslice_by_origin(
        origin: str, metadata_tensorslices: Sequence[MetadataTensorSlice]
    ) -> MetadataTensorSlice:
        for metadata_tensorslice in metadata_tensorslices:
            if metadata_tensorslice.origin == origin:
                return metadata_tensorslice
        raise ValueError(f"Invalid origin {origin} is encountered")

    old_pipeline_input_meta_ts = list(old_pipeline.metadata.tensor_slices.inputs.values())
    for device_idx, comps_on_device in enumerate(slices_of_comps_per_device):
        # A map from origins (in str) to ts names in overriding supertask, previously added
        prev_loaded_tensor_slice_within_device: Dict[str, NameAfterMakeFx] = dict()
        for comp, input_from_pred_supertask in comps_on_device:
            # Updates argument for each CompSuperTask.
            # We need to consider the followings:
            # 1. Parameters and Tensor constants: can be preserved while overriding.
            # 2. Tensor slices: require assigning new tensor slices args, as newly derived partition (through CommSuperTask) of CompSuperTasks can split the application of existing tensor slices.
            #   e.g, if the new pipeline parallelism configuration decides to split the execution of CompSuperTasks A and B, common tensor slice arg over A and B should be spliited into different device.
            # 3. Inter-supertask arguments: restored from the `outputs_of_non_inoutput_spt_lastly_added` in the previous iteration.
            updated_input_names = list()
            # input_from_pred_supertask is `set` instance
            for curr_comp_input_name in comp.inputs:
                if curr_comp_input_name in input_from_pred_supertask:
                    updated_input_names += outputs_of_non_inoutput_spt_lastly_added
                elif curr_comp_input_name in old_pipeline_constant_args:
                    # For constant arguments, retain their names
                    updated_input_names.append(curr_comp_input_name)
                else:
                    origin_of_curr_comp_input = old_input_tensor_slices[curr_comp_input_name].origin
                    if prev_loaded_ts_name_of_same_origin := prev_loaded_tensor_slice_within_device.get(
                        origin_of_curr_comp_input
                    ):
                        ts_name_to_append = prev_loaded_ts_name_of_same_origin
                    else:
                        # Then, it is a tensor slice of unique origin, at least within curerent device context
                        ts_name_to_append = NameAfterMakeFx(
                            f"d{device_idx}_override_ts_{curr_comp_input_name}"
                        )
                        prev_loaded_tensor_slice_within_device[origin_of_curr_comp_input] = (
                            ts_name_to_append
                        )
                    updated_pipeline_tensors[ts_name_to_append] = old_pipeline.tensors[
                        curr_comp_input_name
                    ]
                    updated_input_names.append(ts_name_to_append)
            updated_pipeline_tensors.update({x: old_pipeline.tensors[x] for x in comp.outputs})
            # since we are assuming sequential structure, just append all the output from previous `outputs_of_lastly_added`
            updated_supertask = comp.shallow_copy_with_replaced_device(
                DeviceId(device_idx)
            ).shallow_copy_with_replaced_inputs(updated_input_names)
            updated_non_inoutput_spt.append(updated_supertask)
            outputs_of_non_inoutput_spt_lastly_added = updated_supertask.outputs
        updated_pipeline_meta_tensorslices_input.update(
            {
                overrided_name: get_metadata_tensorslice_by_origin(
                    origin, old_pipeline_input_meta_ts
                ).shallow_copy_with_replaced_device(DeviceId(device_idx))
                for origin, overrided_name in prev_loaded_tensor_slice_within_device.items()
            }
        )

        if device_idx != len(slices_of_comps_per_device) - 1:
            # if it is not the final executed CompSuperTask within the device, add two new CommSuperTask instances: SEND and RECV.
            send_comm_supertask = CommSuperTask(
                kind=SuperTaskKind.SEND,
                inputs=outputs_of_non_inoutput_spt_lastly_added,
                outputs=[],
                device=DeviceId(device_idx),
                device_idx=0,
                metadata={},
                group=str(group_id_cnt),
            )
            updated_non_inoutput_spt.append(send_comm_supertask)
            output_name_for_new_comm_recv = NameAfterMakeFx(f"overriding_recv_{group_id_cnt}")

            # overriding Pipeline.tensors
            assert len(outputs_of_non_inoutput_spt_lastly_added) == 1
            updated_pipeline_tensors[output_name_for_new_comm_recv] = old_pipeline.tensors[
                outputs_of_non_inoutput_spt_lastly_added[0]
            ]
            recv_comm_supertask = CommSuperTask(
                kind=SuperTaskKind.RECV,
                inputs=[],
                outputs=[output_name_for_new_comm_recv],
                device=DeviceId(device_idx + 1),
                device_idx=1,
                metadata={},
                group=str(group_id_cnt),
            )
            updated_non_inoutput_spt.append(recv_comm_supertask)
            group_id_cnt += 1
            outputs_of_non_inoutput_spt_lastly_added = recv_comm_supertask.outputs

    # Generating new InOutputSupertasks for the overriding pipeline
    input_super_tasks = [x for x in old_pipeline.supertasks.values() if SuperTask.is_input(x)]
    assert len(input_super_tasks) == 1
    output_super_tasks = [x for x in old_pipeline.supertasks.values() if SuperTask.is_output(x)]
    assert len(output_super_tasks) == 1
    updated_input_supertask = input_super_tasks[0].shallow_copy_with_replaced_outputs(
        list(updated_pipeline_meta_tensorslices_input.keys())
    )
    updated_output_supertask = output_super_tasks[0].shallow_copy_with_replaced_inputs(
        updated_non_inoutput_spt[-1].outputs
    )

    updated_inoutput_supertasks = [updated_input_supertask, updated_output_supertask]
    updated_supertasks = updated_inoutput_supertasks + updated_non_inoutput_spt

    updated_supertasks_with_id = {
        SuperTaskId(i): supertask for i, supertask in enumerate(updated_supertasks)
    }

    # overriding pipeline metadata
    updated_metadata = MetaData(
        tensors=old_pipeline.metadata.tensors,
        tensor_slices=MetadataTensorSlices(
            inputs=updated_pipeline_meta_tensorslices_input,
            outputs={
                output_name: meta_ts.shallow_copy_with_replaced_device(
                    DeviceId(len(num_blocks_per_pp_stage) - 1)
                )
                for output_name, meta_ts in old_pipeline.metadata.tensor_slices.outputs.items()
            },
        ),
    )
    return (
        old_pipeline.shallow_copy_with_new_devices_and_supertasks(
            new_devices, updated_supertasks_with_id
        )
        .shallow_copy_with_replaced_tensors(updated_pipeline_tensors)
        .shallow_copy_with_replaced_metadata(updated_metadata)
    )
