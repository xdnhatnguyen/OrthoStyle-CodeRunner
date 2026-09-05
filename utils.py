# Copyright 2024 Google LLC
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     https://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.


from train import WurstCoreC
from CSD.model import CSD_CLIP
from CSD.utils import convert_state_dict
from modules.common import LayerNorm2d, Linear
import os
import math
import numpy as np
import torch
import torch.nn as nn
from torch.nn.init import trunc_normal_


class Style_Storage:
  current_step: int = 0
  num_steps: int = 20
  last_logged_step: int = -1
  mu_s: float = 0.0

def setup_csd(device: str = "cpu") -> nn.Module:
  """Sets up the CSD model.

  Args:
      device: The device to load the model onto.

  Returns:
      The initialized CSD model.
  """
  model_path = os.environ.get("CSD_CHECKPOINT_PATH", "third_party/CSD/checkpoint.pth")
  if not os.path.exists(model_path):
      for fallback in [
          "third_party/CSD/checkpoint.pth",
          "../third_party/CSD/checkpoint.pth",
          os.path.join(os.environ.get("PROJECT_ROOT", "."), "third_party/CSD/checkpoint.pth"),
      ]:
          if os.path.exists(fallback):
              model_path = fallback
              break
  model = CSD_CLIP("vit_large", "default")
  checkpoint = torch.load(model_path, map_location=device, weights_only=False)
  state_dict = convert_state_dict(checkpoint["model_state_dict"])
  print("CSD model loading ...")
  msg = model.load_state_dict(state_dict, strict=True)
  print(msg)
  model.eval()
  return model


class WurstCoreCRBM(WurstCoreC):

  def extract_conditions(
      self,
      batch: dict,
      models: WurstCoreC.Models,
      extras: WurstCoreC.Extras,
      is_eval: bool = False,
      is_unconditional: bool = False,
      eval_image_embeds: bool = False,
      eval_style: bool = False,
      eval_style_pooled: bool = False,
      eval_subject_style: bool = False,
      eval_csd: bool = False,
      return_fields: list[str] = None,
  ) -> dict:
    """Extracts conditions from the input batch.

    Args:
        batch: Input batch of data.
        models: Models for extraction.
        extras: Extra utilities for preprocessing.
        is_eval: Flag for evaluation mode.
        is_unconditional: Flag for unconditional generation.
        eval_image_embeds: Flag for evaluating image embeddings.
        eval_style: Flag for evaluating style embeddings.
        eval_style_pooled: Flag for evaluating pooled style embeddings.
        eval_subject_style: Flag for evaluating subject style embeddings.
        eval_csd: Flag for evaluating CSD model.
        return_fields: list[str] - List of fields to return.

    Returns:
        Extracted conditions.
    """

    if return_fields is None:
      return_fields = ["clip_text", "clip_text_pooled", "clip_img"]

    captions = batch.get("captions", None)
    images = batch.get("images", None)
    style = batch.get("style", None)
    batch_size = len(captions)

    text_embeddings = None
    text_pooled_embeddings = None
    if "clip_text" in return_fields or "clip_text_pooled" in return_fields:
      if is_eval:
        if is_unconditional:
          captions_unpooled = ["" for _ in range(batch_size)]
        else:
          captions_unpooled = captions
      else:
        rand_idx = np.random.rand(batch_size) > 0.05
        captions_unpooled = [
            str(c) if keep else "" for c, keep in zip(captions, rand_idx)
        ]
      clip_tokens_unpooled = models.tokenizer(
          captions_unpooled,
          truncation=True,
          padding="max_length",
          max_length=models.tokenizer.model_max_length,
          return_tensors="pt",
      ).to(self.device)
      text_encoder_output = models.text_model(
          **clip_tokens_unpooled, output_hidden_states=True
      )
      if "clip_text" in return_fields:
        text_embeddings = text_encoder_output.hidden_states[-1]
      if "clip_text_pooled" in return_fields:
        text_pooled_embeddings = text_encoder_output.text_embeds.unsqueeze(1)

    return_fields_dict = {
        "clip_text": text_embeddings,
        "clip_text_pooled": text_pooled_embeddings,
    }

    style_embeddings = None
    if "clip_style" in return_fields:
      style_embeddings = torch.zeros(batch_size, 768, device=self.device)
      if style is not None:
        style = style.to(self.device)
        if is_eval:
          if not is_unconditional and eval_image_embeds and eval_style:
            if eval_csd:
              # AFA w/ CSD is more efficient.
              csd_model = setup_csd(device=self.device)
              bb_feats1, content_embeddings, style_embeddings = csd_model(
                  extras.clip_preprocess(style)
              )
            else:
              style_embeddings = models.image_model(
                  extras.clip_preprocess(style)
              ).image_embeds
        else:
          rand_idx = np.random.rand(batch_size) > 0.9
          if any(rand_idx):
            style_embeddings[rand_idx] = models.image_model(
                extras.clip_preprocess(style[rand_idx])
            ).image_embeds
      style_embeddings = style_embeddings.unsqueeze(1)
      return_fields_dict["clip_style"] = style_embeddings

      if "clip_style_pooled" in return_fields and eval_style_pooled:
        return_fields_dict["clip_style_pooled"] = torch.cat(
            [style_embeddings.mean(axis=0).unsqueeze(dim=0)] * batch_size, dim=0
        )
    else:
      image_embeddings = None
      image_embeddings = torch.zeros(batch_size, 768, device=self.device)
      if images is not None:
        images = images.to(self.device)
        if is_eval:
          if not is_unconditional and eval_image_embeds:
            image_embeddings = models.image_model(
                extras.clip_preprocess(images)
            ).image_embeds
        else:
          rand_idx = np.random.rand(batch_size) > 0.9
          if any(rand_idx):
            image_embeddings[rand_idx] = models.image_model(
                extras.clip_preprocess(images[rand_idx])
            ).image_embeds
      image_embeddings = image_embeddings.unsqueeze(1)
      return_fields_dict["clip_img"] = image_embeddings

      style_embeddings = None
      if "clip_img_style" in return_fields:
        style_embeddings = torch.zeros(batch_size, 768, device=self.device)
        if style is not None:
          style = style.to(self.device)
          if is_eval:
            if (
                not is_unconditional
                and eval_image_embeds
                and eval_subject_style
            ):
              if eval_csd:
                # AFA w/ csd.
                csd_model = setup_csd(device=self.device)
                bb_feats1, content_embeddings, style_embeddings = csd_model(
                    extras.clip_preprocess(style)
                )
              else:
                style_embeddings = models.image_model(
                    extras.clip_preprocess(style)
                ).image_embeds
          else:
            rand_idx = np.random.rand(batch_size) > 0.9
            if any(rand_idx):
              style_embeddings[rand_idx] = models.image_model(
                  extras.clip_preprocess(style[rand_idx])
              ).image_embeds
        style_embeddings = style_embeddings.unsqueeze(1)
        return_fields_dict["clip_img_style"] = style_embeddings
    return return_fields_dict

  def get_conditions(
      self,
      batch: dict,
      models: WurstCoreC.Models,
      extras: WurstCoreC.Extras,
      is_eval: bool = False,
      is_unconditional: bool = False,
      eval_image_embeds: bool = False,
      eval_style: bool = False,
      eval_style_pooled: bool = False,
      eval_subject_style: bool = False,
      eval_csd: bool = False,
      return_fields: list[str] = None,
  ) -> dict:
    """Retrieves conditions from the input batch.

    Args:
        batch: Input batch of data.
        models: Models for extraction.
        extras: Extra utilities for preprocessing.
        is_eval: Flag for evaluation mode.
        is_unconditional: Flag for unconditional generation.
        eval_image_embeds: Flag for evaluating image embeddings.
        eval_style: Flag for evaluating style embeddings.
        eval_style_pooled: Flag for evaluating pooled style embeddings.
        eval_subject_style: Flag for evaluating subject style embeddings.
        eval_csd: Flag for evaluating CSD model.
        return_fields: List of fields to return.

    Returns:
        Extracted conditions.
    """
    if eval_style:
      if eval_style_pooled:
        conditions = self.extract_conditions(
            batch,
            models,
            extras,
            is_eval,
            is_unconditional,
            eval_image_embeds,
            eval_style=eval_style,
            eval_style_pooled=eval_style_pooled,
            eval_csd=eval_csd,
            return_fields=return_fields
            or [
                "clip_text",
                "clip_text_pooled",
                "clip_style",
                "clip_style_pooled",
            ],
        )
      else:
        conditions = self.extract_conditions(
            batch,
            models,
            extras,
            is_eval,
            is_unconditional,
            eval_image_embeds,
            eval_style=eval_style,
            eval_csd=eval_csd,
            return_fields=return_fields
            or ["clip_text", "clip_text_pooled", "clip_style"],
        )
    elif eval_subject_style:
      conditions = self.extract_conditions(
          batch,
          models,
          extras,
          is_eval,
          is_unconditional,
          eval_image_embeds,
          eval_subject_style=eval_subject_style,
          eval_csd=eval_csd,
          return_fields=return_fields
          or ["clip_text", "clip_text_pooled", "clip_img", "clip_img_style"],
      )
    else:
      conditions = self.extract_conditions(
          batch,
          models,
          extras,
          is_eval,
          is_unconditional,
          eval_image_embeds,
          return_fields=return_fields
          or ["clip_text", "clip_text_pooled", "clip_img"],
      )

    return conditions


class Attention2D(nn.Module):
  """Attention2D module with Attention Feature Aggregation (AFA)."""

  def __init__(self, c: int, nhead: int, dropout: float = 0.0) -> None:
    """Creates the Attention2D module.

    Args:
        c: Number of channels.
        nhead: Number of attention heads.
        dropout: Dropout rate.
    """
    super().__init__()
    self.attn = nn.MultiheadAttention(
        c, nhead, dropout=dropout, bias=True, batch_first=True
    )

  def forward(
      self,
      x: torch.Tensor,
      kv: torch.Tensor,
      self_attn: bool = False,
      style: bool = False,
      img_style: bool = False,
      clip_size: int = 4,
      i: int = None,
      num_steps: int = None,
  ) -> torch.Tensor:
    """Forward pass of the Attention2D module.

    Args:
        x: Input tensor.
        kv: Key-value tensor.
        self_attn: Flag for self-attention.
        style: Flag for style attention.
        img_style: Flag for content style attention.
        clip_size: Size of the clip.
        i: Current step index.
        num_steps: Total number of steps.

    Returns:
        Output tensor.
    """
    att_map = None
    orig_shape = x.shape
    x = x.view(x.size(0), x.size(1), -1).permute(
        0, 2, 1
    )  # shape: [B, H*W, C]

    if self_attn:
      kv = torch.cat([x, kv], dim=1)  # shape: [B, Seq_all, C]
    if style:
      mean = kv[:, -clip_size:, :].mean(axis=1).unsqueeze(dim=1)  # shape: [B, 1, C]
      ## for style only
      kv[:, -clip_size:, :] = torch.cat([mean] * (clip_size), dim=1)  # shape: [B, Seq, C]

      # KV for text only to better align with the prompt
      x_txt = self.attn(
          x, kv[:, :-clip_size, :], kv[:, :-clip_size, :], need_weights=False
      )[0]  # shape: [B, H*W, C]

      # KV for text+reference_style(img)
      x_txt_style = self.attn(x, kv, kv, need_weights=False)[0]  # shape: [B, H*W, C]

      # KV for reference_style(img)
      kv[:, -2 * clip_size : -clip_size, :] = kv[:, -clip_size:, :]  # shape: [B, Seq, C]
      x_style = self.attn(
          x, kv[:, :-clip_size, :], kv[:, :-clip_size, :], need_weights=False
      )[0]  # shape: [B, H*W, C]

      ## simple average
      x = (x_txt + x_txt_style + x_style) / 3  # shape: [B, H*W, C]
    elif img_style:
      # Adaptive Attention Weights qua Hàm Sigmoid
      i = getattr(Style_Storage, "current_step", 0) if i is None else i
      num_steps = getattr(Style_Storage, "num_steps", 20) if num_steps is None else num_steps

      p = i / num_steps
      p_switch = float(os.environ.get("P_SWITCH", "0.10"))
      k_steepness = 50.0
      S_p = 1.0 / (1.0 + math.exp(-k_steepness * (p - p_switch)))
      w_txt = 0.0
      w_sub = 1.0 - (0.85 * S_p)
      w_style = 0.45 * S_p
      w_sub_style = 0.40 * S_p

      alpha_style = float(os.environ.get("ALPHA_STYLE", "0.85"))
      style_tokens = kv[:, -clip_size:, :].clone()  # shape: [B, clip_size, C]

      # Null Space Projection qua SVD trên Token Covariance
      # content_tokens = kv[:, :-clip_size, :]  # shape: [B, Seq - clip_size, C]
      # cent_style = style_tokens - style_tokens.mean(dim=1, keepdim=True)  # shape: [B, clip_size, C]
      # cent_content = content_tokens - content_tokens.mean(dim=1, keepdim=True)  # shape: [B, Seq - clip_size, C]

      # cov_style = torch.bmm(cent_style.transpose(1, 2), cent_style) / (cent_style.shape[1] - 1)  # shape: [B, C, C]
      # cov_content = torch.bmm(cent_content.transpose(1, 2), cent_content) / (cent_content.shape[1] - 1)  # shape: [B, C, C]

      # U_s, _, V_s = torch.svd(cov_style.float())  # shape: [B, C, C]
      # U_c, _, V_c = torch.svd(cov_content.float())  # shape: [B, C, C]

      # V_s = V_s.to(dtype=style_tokens.dtype)  # shape: [B, C, C]
      # V_c = V_c.to(dtype=style_tokens.dtype)  # shape: [B, C, C]

      # style_tokens_null = torch.bmm(style_tokens, V_s)  # shape: [B, clip_size, C]
      # style_tokens_aligned = torch.bmm(style_tokens_null, V_c.transpose(1, 2))  # shape: [B, clip_size, C]
      # style_tokens = style_tokens_aligned  # shape: [B, clip_size, C]

      mean = style_tokens.mean(axis=1).unsqueeze(dim=1)  # shape: [B, 1, C]
      blended_style = alpha_style * style_tokens + (1 - alpha_style) * torch.cat([mean] * clip_size, dim=1)  # shape: [B, clip_size, C]

      kv_txt = kv.clone()  # shape: [B, Seq, C]
      x_txt = self.attn(
          x,
          kv_txt[:, : -2 * clip_size, :],
          kv_txt[:, : -2 * clip_size, :],
          need_weights=False,
      )[0]  # shape: [B, H*W, C]

      kv_sub = kv.clone()  # shape: [B, Seq, C]
      x_sub = self.attn(
          x, kv_sub[:, :-clip_size, :], kv_sub[:, :-clip_size, :], need_weights=False
      )[0]  # shape: [B, H*W, C]

      kv_mixed = kv.clone()  # shape: [B, Seq, C]
      kv_mixed[:, -clip_size:, :] = blended_style  # shape: [B, Seq, C]
      x_sub_style, att_map = self.attn(x, kv_mixed, kv_mixed, need_weights=True)  # shape: [B, H*W, C]

      kv_pure_style = kv.clone()  # shape: [B, Seq, C]
      kv_pure_style[:, -2 * clip_size : -clip_size, :] = blended_style  # shape: [B, Seq, C]
      x_style = self.attn(
          x, kv_pure_style[:, :-clip_size, :], kv_pure_style[:, :-clip_size, :], need_weights=False
      )[0]  # shape: [B, H*W, C]

      x = (w_txt * x_txt) + (w_sub * x_sub) + (w_style * x_style) + (w_sub_style * x_sub_style)  # shape: [B, H*W, C]
      if i in [0, 1, 2, 3, 4, 15] and Style_Storage.last_logged_step != i:
        print(f"[Adaptive Sigmoid Weights] Step i={i}: S_p={S_p:.4f}, w_sub={w_sub:.4f}, w_style={w_style:.4f}")
        Style_Storage.last_logged_step = i
  #   elif img_style:
  #     mean = kv[:, -clip_size:, :].mean(axis=1).unsqueeze(dim=1)

  #     ## for txt, helps in extreme style transfer
  #     x_txt = self.attn(
  #         x,
  #         kv[:, : -2 * clip_size, :],
  #         kv[:, : -2 * clip_size, :],
  #         need_weights=False,
  #     )[0]

  #     ## for sub
  #     x_sub = self.attn(
  #         x, kv[:, :-clip_size, :], kv[:, :-clip_size, :], need_weights=False
  #     )[0]

  #     ## for sub_style
  #     kv[:, -clip_size:, :] = torch.cat([mean] * (clip_size), dim=1)
  #     x_sub_style, att_map = self.attn(x, kv, kv, need_weights=True)

  #     ## for style
  #     kv[:, -2 * clip_size : -clip_size, :] = torch.cat(
  #         [mean] * (clip_size), dim=1
  #     )
  #     x_style = self.attn(
  #         x, kv[:, :-clip_size, :], kv[:, :-clip_size, :], need_weights=False
  #     )[0]

  #     ## simple averaging
  #     x = (x_txt + x_sub + x_style + x_sub_style) / 4
    else:
      x = self.attn(x, kv, kv, need_weights=False)[0]
    x = x.permute(0, 2, 1).view(*orig_shape)
    return x


class AttnBlock(nn.Module):
  """Attention block with Attention Feature Aggregation (AFA)."""

  def __init__(
      self,
      c: int,
      c_cond: int,
      nhead: int,
      self_attn: bool = True,
      dropout: float = 0.0,
  ) -> None:
    """Initializes the AttnBlock module.

    Args:
        c: Number of channels.
        c_cond: Number of conditional channels.
        nhead: Number of attention heads.
        self_attn: Flag for self-attention.
        dropout: Dropout rate.
    """
    super().__init__()
    self.self_attn = self_attn
    self.norm = LayerNorm2d(c, elementwise_affine=False, eps=1e-6)
    self.attention = Attention2D(c, nhead, dropout)
    self.kv_mapper = nn.Sequential(nn.SiLU(), Linear(c_cond, c))

  def forward(
      self,
      x: torch.Tensor,
      kv: torch.Tensor,
      style: bool = False,
      img_style: bool = False,
      i: int = None,
      num_steps: int = None,
  ) -> torch.Tensor:
    """Forward pass of the AttnBlock module.

    Args:
        x: Input tensor.
        kv: Key-value tensor.
        style: Flag for style attention.
        img_style: Flag for content style attention.
        i: Current step index.
        num_steps: Total number of steps.

    Returns:
        Output tensor.
    """
    kv = self.kv_mapper(kv)  # shape: [B, Seq, C]
    x_out = self.attention(
        self.norm(x),  # shape: [B, C, H, W]
        kv,  # shape: [B, Seq, C]
        self_attn=self.self_attn,
        style=style,
        img_style=img_style,
        i=i,
        num_steps=num_steps,
    )  # shape: [B, C, H, W]
    x = x + x_out  # shape: [B, C, H, W]
    return x  # shape: [B, C, H, W]
