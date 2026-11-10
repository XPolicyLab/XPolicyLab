"""Use fixed pretrained RGB cosine matching inside the retained sorting program."""
from pathlib import Path
from types import FunctionType, SimpleNamespace
import time
import numpy as np
from scipy.optimize import linear_sum_assignment
from coap.tasks import memory as parent_memory
from coap.tasks import sorting_r01_d as parent_D


MODEL_REVISION = 'ed25f3a31f01632728cabb09d1542f84ab7b0056'
_MODEL = None
_PROCESSOR = None


def _load_encoder():
    """Read only the packaged public snapshot, without network or external cache use."""
    global _MODEL, _PROCESSOR
    if _MODEL is None:
        from transformers import Dinov2Model, AutoImageProcessor
        folder = Path(__file__).resolve().parents[1] / 'assets' / 'sorting_dinov2_small'
        _PROCESSOR = AutoImageProcessor.from_pretrained(str(folder), local_files_only=True,
                                                      trust_remote_code=False)
        _MODEL = Dinov2Model.from_pretrained(str(folder), local_files_only=True,
                                           trust_remote_code=False).eval().cpu()
        for parameter in _MODEL.parameters():
            parameter.requires_grad_(False)
    return _MODEL, _PROCESSOR


def _encode(crops):
    """Preserve full crops and average the same four normalized CLS rotations."""
    import torch
    from PIL import Image, ImageOps
    model, processor = _load_encoder()
    pictures = []
    for crop in crops:
        square = ImageOps.pad(Image.fromarray(np.asarray(crop, np.uint8)).convert('RGB'),
                              (224, 224), method=Image.Resampling.BICUBIC, color=(128, 128, 128))
        pictures.extend(square.rotate(angle) for angle in (0, 90, 180, 270))
    inputs = processor(images=pictures, return_tensors='pt', do_resize=False, do_center_crop=False)
    with torch.inference_mode():
        features = model(**inputs).last_hidden_state[:, 0].float()
        features = torch.nn.functional.normalize(features, dim=-1)
        features = features.reshape(len(crops), 4, -1).mean(1)
        features = torch.nn.functional.normalize(features, dim=-1)
    return features.numpy()


def pair_objects(image, targets, demonstrations, demonstration_image=None, return_evidence=False):
    """Rank only the fixed cosine matrix; retain parent grasp annotations for chosen pairs."""
    demonstration_image = image if demonstration_image is None else demonstration_image
    crops = [parent_memory.crop_of(*parent_memory.measured_view(image, obj)) for obj in targets]
    crops += [parent_memory.crop_of(*parent_memory.measured_view(demonstration_image, obj))
              for obj in demonstrations]
    started = time.perf_counter()
    features = _encode(crops)
    costs = 1. - features[:len(targets)] @ features[len(targets):].T
    rows, cols = linear_sum_assignment(costs)
    elapsed = time.perf_counter() - started
    pairs = {int(j): targets[int(i)] for i, j in zip(rows, cols)}
    if not return_evidence:
        return pairs
    # Force only the parent's first assignment to obtain its existing per-pair grasp metadata.
    # Subsequent calls are the parent's informational alternate-assignment computations.
    calls = 0
    def selected_assignment(matrix):
        nonlocal calls
        calls += 1
        return (rows.copy(), cols.copy()) if calls == 1 else linear_sum_assignment(matrix)
    namespace = dict(parent_memory.pair_objects.__globals__)
    namespace['linear_sum_assignment'] = selected_assignment
    original = parent_memory.pair_objects
    metadata_pair = FunctionType(original.__code__, namespace, original.__name__,
                                 original.__defaults__, original.__closure__)
    metadata_pair.__kwdefaults__ = original.__kwdefaults__
    _, evidence = metadata_pair(image, targets, demonstrations, demonstration_image, True)
    total = float(costs[rows, cols].sum())
    for assignment in evidence['assignments']:
        i, j = assignment['source_id'], assignment['demonstration_id']
        alternate = costs.copy()
        alternate[i, j] = 1e6
        alt_rows, alt_cols = linear_sum_assignment(alternate)
        margin = float(alternate[alt_rows, alt_cols].sum() - total)
        assignment.update(pair_cost=float(costs[i, j]), global_assignment_margin=margin,
                          ambiguous_assignment=margin < .10)
    evidence.update(method='fixed_dinov2_small_four_rotation_cls_cosine', assignment_cost=total,
                    model_revision=MODEL_REVISION, feature_dimensions=int(features.shape[1]),
                    rotation_degrees=[0, 90, 180, 270], letterbox_size=224,
                    pure_cosine_assignment=True, parent_grasp_metadata_retained=True,
                    model_and_inference_seconds=float(elapsed), packaged_local_weights_only=True,
                    runtime_gates_added=False)
    return pairs, evidence


def build_core(core):
    """Keep existing private bindings while replacing only the initial pair function."""
    namespace = dict(core.__globals__)
    original = namespace['memory'].run
    memory_globals = dict(original.__globals__)
    memory_globals['pair_objects'] = pair_objects
    private_run = FunctionType(original.__code__, memory_globals, original.__name__,
                               original.__defaults__, original.__closure__)
    private_run.__kwdefaults__ = original.__kwdefaults__
    namespace['memory'] = SimpleNamespace(run=private_run)
    private_core = FunctionType(core.__code__, namespace, core.__name__,
                                core.__defaults__, core.__closure__)
    private_core.__kwdefaults__ = core.__kwdefaults__
    return private_core


def run(ctx):
    """Preserve the retained initializer, observation protocol and replay actions."""
    yield from build_core(parent_D.run)(ctx)
