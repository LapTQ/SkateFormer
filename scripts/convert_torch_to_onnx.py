import torch
from torch import nn
import os
import sys
from pathlib import Path

sys.path.append(str(Path(__file__).parent.parent))

from collections import OrderedDict
from model.SkateFormer import SkateFormer_

# Configure the models to convert here.
# For single model conversion, just provide one item in the OrderedDict.
# For ensemble conversion, provide multiple items.
model_paths = OrderedDict(
    [
        (
            "j",
            "/home/laptq/laptq-fs26-shoplifting-detection/runs/SkateFormer/fs26/v219--satudora_veo3_awlrecord--split-14-class--nodistinct--2s-15frames--v2/model_8/best.pt",
        ),
        (
            "b",
            "/home/laptq/laptq-fs26-shoplifting-detection/runs/SkateFormer/fs26/v220--satudora_veo3_awlrecord--split-14-class--nodistinct--2s-15frames--v2--b/model_3/best.pt",
        ),
        (
            "jm",
            "/home/laptq/laptq-fs26-shoplifting-detection/runs/SkateFormer/fs26/v221--satudora_veo3_awlrecord--split-14-class--nodistinct--2s-15frames--v2--jm/model_1/best.pt",
        ),
        (
            "bm",
            "/home/laptq/laptq-fs26-shoplifting-detection/runs/SkateFormer/fs26/v222--satudora_veo3_awlrecord--split-14-class--nodistinct--2s-15frames--v2--bm/model_3/best.pt",
        ),
    ]
)

pathf_output = "/home/laptq/laptq-fs26-shoplifting-detection/outputs/convert-torch-to-onnx/fs26/SkateFormer/{}.onnx".format(
    "--".join(
        [
            "{}-{}".format(path.split("/")[-3].split("--")[0], key)
            for key, path in model_paths.items()
        ]
    )
)


dummy_input_shape = (5, 2, 15, 12)
B, C, T, V = dummy_input_shape
dummy_keypoint = torch.randn(dummy_input_shape)

# Example inputs
example_inputs = (
    dummy_keypoint,
    None,  # index_t
    "coco_headless",  # to_layout (set this if we're assuming the input is not already in coco_headless layout, else None)
)

ls_models = OrderedDict()
for key, model_path in model_paths.items():
    model = SkateFormer_(
        in_channels=2,
        num_classes=14,
        num_points=12,
        type_1_size=[4, 3],
        type_2_size=[4, 4],
        type_3_size=[4, 3],
        type_4_size=[4, 4],
        num_people=1,
        kernel_size=7,
        num_heads=32,
        attn_drop=0.5,
        head_drop=0.0,
        rel=True,
        drop_path=0.2,
        mlp_ratio=4.0,
        index_t=True,
    )

    with torch.no_grad():
        model(dummy_keypoint, None)

    weights = torch.load(model_path)
    weights = OrderedDict([[k.split("module.")[-1], v] for k, v in weights.items()])
    model.load_state_dict(weights)
    model.eval()
    ls_models[key] = model

# headless
bone_pairs = (
    (0, 1),
    (1, 0),
    (2, 0),
    (3, 2),
    (4, 2),
    (5, 3),
    (6, 0),
    (7, 1),
    (8, 6),
    (9, 7),
    (10, 8),
    (11, 9),
)


class EnsembleModel(nn.Module):
    def __init__(self, ls_models):
        super().__init__()
        self.model_j = ls_models.get("j", None)
        self.model_b = ls_models.get("b", None)
        self.model_jm = ls_models.get("jm", None)
        self.model_bm = ls_models.get("bm", None)

    def forward(self, x, index_t, to_layout):
        B, C, T, V = x.shape

        x_j = x

        x_b = torch.zeros_like(x_j)
        for v1, v2 in bone_pairs:
            x_b[..., v1] = x_j[..., v1] - x_j[..., v2]

        x_jm = torch.zeros_like(x_j)
        x_jm[..., : T - 1, :] = x_j[..., 1:, :] - x_j[..., : T - 1, :]

        x_bm = torch.zeros_like(x_b)
        x_bm[..., : T - 1, :] = x_b[..., 1:, :] - x_b[..., : T - 1, :]

        if self.model_j is not None:
            output_j, feat_j = self.model_j(x_j, index_t, to_layout)
        else:
            output_j, feat_j = None, None
        if self.model_b is not None:
            output_b, feat_b = self.model_b(x_b, index_t, to_layout)
        else:
            output_b, feat_b = None, None
        if self.model_jm is not None:
            output_jm, feat_jm = self.model_jm(x_jm, index_t, to_layout)
        else:
            output_jm, feat_jm = None, None
        if self.model_bm is not None:
            output_bm, feat_bm = self.model_bm(x_bm, index_t, to_layout)
        else:
            output_bm, feat_bm = None, None

        return [
            i
            for p in [
                [
                    output_j,
                    # feat_j,
                ],
                [
                    output_b,
                    # feat_b,
                ],
                [
                    output_jm,
                    # feat_jm,
                ],
                [
                    output_bm,
                    # feat_bm,
                ],
            ]
            for i in p
            if p[0] is not None
        ]


model = EnsembleModel(ls_models)


os.makedirs(os.path.dirname(pathf_output), exist_ok=True)

output_names = [
    it
    for p in [
        (
            f"output_{key}",
            # f"feat_{key}",
        )
        for key in ls_models.keys()
    ]
    for it in p
]

# Export to ONNX
torch.onnx.export(
    model,
    example_inputs,
    pathf_output,
    input_names=[
        "input1",
    ],
    output_names=output_names,
    dynamic_axes={
        "input1": {
            0: "batch_size",
        },
        **{it: {0: "batch_size"} for it in output_names},
    },
    opset_version=12,
)

print("Model exported to {}".format(pathf_output))

# --minShapes=input1:1x2x16x12x1,input2:16 --optShapes=input1:16x2x16x12x1,input2:16 --maxShapes=input1:32x2x16x12x1,input2:16 --shapes=input1:5x2x16x12x1,input2:16

import onnxruntime as ort
import onnx
import numpy as np


class ONNXPredictor:

    def __init__(self, **kwargs):
        model_path = kwargs["model_path"]
        enable_CUDAExecutionProvider = kwargs["enable_CUDAExecutionProvider"]
        enable_CPUExecutionProvider = kwargs["enable_CPUExecutionProvider"]

        providers = []
        if enable_CUDAExecutionProvider:
            providers.append("CUDAExecutionProvider")
        if enable_CPUExecutionProvider:
            providers.append("CPUExecutionProvider")

        self.model = onnx.load(model_path)
        self.session = ort.InferenceSession(
            model_path,
            providers=providers,
        )

        onnx.checker.check_model(self.model)

    def predict(self, inputs, output_names):
        inputs = {name: np.array(inputs[name], dtype=np.float32) for name in inputs}
        outputs = self.session.run(output_names, inputs)
        outputs = {name: outputs[i] for i, name in enumerate(output_names)}
        return {"outputs": outputs}


predictor = ONNXPredictor(
    model_path=pathf_output,
    enable_CUDAExecutionProvider=True,
    enable_CPUExecutionProvider=False,
)

print(
    predictor.predict(
        inputs={
            "input1": np.random.randn(13, 2, 15, 12),
        },
        output_names=output_names,
    )
)
