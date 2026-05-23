# Copyright (c) Meta Platforms, Inc. and affiliates.

import os
from pathlib import Path

import torch
from torch import nn


class Dinov3Backbone(nn.Module):
    def __init__(
        self, name="dinov2_vitb14", pretrained_weight=None, cfg=None, *args, **kwargs
    ):
        super().__init__()
        self.name = name
        self.cfg = cfg

        dinov3_repo = _resolve_local_dinov3_repo()
        if dinov3_repo is not None:
            self.encoder = torch.hub.load(
                str(dinov3_repo),
                self.name,
                source="local",
                pretrained=False,
                drop_path=self.cfg.MODEL.BACKBONE.DROP_PATH_RATE,
            )
        else:
            self.encoder = torch.hub.load(
                "facebookresearch/dinov3",
                self.name,
                source="github",
                pretrained=False,
                drop_path=self.cfg.MODEL.BACKBONE.DROP_PATH_RATE,
            )
        self.patch_size = self.encoder.patch_size
        self.embed_dim = self.embed_dims = self.encoder.embed_dim

    def forward(self, x, extra_embed=None):
        """
        Encode a RGB image using a ViT-backbone
        Args:
            - x: torch.Tensor of shape [bs,3,w,h]
        Return:
            - y: torch.Tensor of shape [bs,k,d] - image in patchified mode
        """
        assert extra_embed is None, "Not Implemented Yet"

        y = self.encoder.get_intermediate_layers(x, n=1, reshape=True, norm=True)[-1]

        return y

    def get_layer_depth(self, param_name: str, prefix: str = "encoder."):
        """Get the layer-wise depth of a parameter.
        Args:
            param_name (str): The name of the parameter.
            prefix (str): The prefix for the parameter.
                Defaults to an empty string.
        Returns:
            Tuple[int, int]: The layer-wise depth and the num of layers.
        Note:
            The first depth is the stem module (``layer_depth=0``), and the
            last depth is the subsequent module (``layer_depth=num_layers-1``)
        """
        num_layers = self.encoder.n_blocks + 2

        if not param_name.startswith(prefix):
            # For subsequent module like head
            return num_layers - 1, num_layers

        param_name = param_name[len(prefix) :]

        if param_name in ("cls_token", "pos_embed", "storage_tokens"):
            layer_depth = 0
        elif param_name.startswith("patch_embed"):
            layer_depth = 0
        elif param_name.startswith("blocks"):
            layer_id = int(param_name.split(".")[1])
            layer_depth = layer_id + 1
        else:
            layer_depth = num_layers - 1

        return layer_depth, num_layers


def _resolve_local_dinov3_repo() -> Path | None:
    override = os.environ.get("DINOV3_REPO_PATH", "").strip()
    if override:
        path = Path(override).expanduser().resolve()
        if (path / "hubconf.py").exists():
            return path
    candidate = Path(torch.hub.get_dir()).expanduser() / "facebookresearch_dinov3_main"
    if (candidate / "hubconf.py").exists():
        return candidate
    return None
