"""Vision Transformer (Dosovitskiy et al., ICLR 2021) — student implementation.

ViT-S/16: patch=16, dim=384, depth=12, heads=6, mlp_ratio=4.

References (read, do NOT import):
    https://arxiv.org/abs/2010.11929
    https://github.com/google-research/vision_transformer
"""
from __future__ import annotations

import torch
from torch import nn

from src.models.heads import MultiTaskHead


class PatchEmbed(nn.Module):
    """Conv-based patch tokenizer (kernel=stride=patch_size)."""

    def __init__(self, img_size: int = 224, patch_size: int = 16, in_c: int = 3, dim: int = 384) -> None:
        super().__init__()
        self.num_patches = (img_size // patch_size) ** 2
        # TODO: a single Conv2d with kernel_size=stride=patch_size, out=dim.
        self.proj = nn.Conv2d(in_c, dim, kernel_size=patch_size, stride=patch_size)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # Output shape: (B, num_patches, dim)
        x = self.proj(x)        # (B, dim, H/P, W/P)
        x = x.flatten(2)        # (B, dim, num_patches)
        x = x.transpose(1, 2)  # (B, num_patches, dim)
        return x


class MultiHeadSelfAttention(nn.Module):
    def __init__(self, dim: int, num_heads: int, attn_drop: float = 0.0, proj_drop: float = 0.0) -> None:
        super().__init__()
        assert dim % num_heads == 0
        self.num_heads = num_heads
        self.head_dim = dim // num_heads
        self.scale = self.head_dim ** -0.5

        # TODO: qkv = Linear(dim, dim*3, bias=True); proj = Linear(dim, dim);
        # attn_drop = Dropout(attn_drop); proj_drop = Dropout(proj_drop).
        self.qkv = nn.Linear(dim, dim * 3, bias=True)
        self.proj = nn.Linear(dim, dim)
        self.attn_drop = nn.Dropout(attn_drop)
        self.proj_drop = nn.Dropout(proj_drop)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # x: (B, N, D)
        B, N, D = x.shape
        # 1) qkv projection -> reshape into (3, B, num_heads, N, head_dim)
        qkv = self.qkv(x).reshape(B, N, 3, self.num_heads, self.head_dim).permute(2, 0, 3, 1, 4)
        q, k, v = qkv.unbind(0)  # each: (B, num_heads, N, head_dim)
        # 2) attention = softmax(q @ k^T * scale)
        attn = (q @ k.transpose(-2, -1)) * self.scale
        attn = self.attn_drop(attn.softmax(dim=-1))
        # 3) out = attention @ v -> reshape back to (B, N, D)
        out = (attn @ v).transpose(1, 2).reshape(B, N, D)
        # 4) proj + proj_drop
        return self.proj_drop(self.proj(out))


class TransformerBlock(nn.Module):
    def __init__(self, dim: int, num_heads: int, mlp_ratio: float = 4.0, drop: float = 0.0, attn_drop: float = 0.0) -> None:
        super().__init__()
        self.norm1 = nn.LayerNorm(dim)
        self.attn = MultiHeadSelfAttention(dim, num_heads, attn_drop=attn_drop, proj_drop=drop)
        self.norm2 = nn.LayerNorm(dim)
        hidden = int(dim * mlp_ratio)
        self.mlp = nn.Sequential(
            nn.Linear(dim, hidden),
            nn.GELU(),
            nn.Dropout(drop),
            nn.Linear(hidden, dim),
            nn.Dropout(drop),
        )

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # Pre-norm residual:
        #   x = x + attn(norm1(x))
        #   x = x + mlp(norm2(x))
        x = x + self.attn(self.norm1(x))
        x = x + self.mlp(self.norm2(x))
        return x


class ViT(nn.Module):
    def __init__(
        self,
        img_size: int = 224,
        patch_size: int = 16,
        dim: int = 384,
        depth: int = 12,
        num_heads: int = 6,
        mlp_ratio: float = 4.0,
        drop: float = 0.0,
        attn_drop: float = 0.0,
        head_dropout: float = 0.1,
    ) -> None:
        super().__init__()
        self.patch_embed = PatchEmbed(img_size, patch_size, 3, dim)
        n_tokens = self.patch_embed.num_patches + 1  # + CLS

        self.cls_token = nn.Parameter(torch.zeros(1, 1, dim))
        self.pos_embed = nn.Parameter(torch.zeros(1, n_tokens, dim))
        self.pos_drop = nn.Dropout(drop)

        self.blocks = nn.ModuleList([
            TransformerBlock(dim, num_heads, mlp_ratio, drop, attn_drop)
            for _ in range(depth)
        ])
        self.norm = nn.LayerNorm(dim)

        self.head = MultiTaskHead(in_features=dim, dropout=head_dropout)

        self._init_weights()

    def _init_weights(self) -> None:
        nn.init.trunc_normal_(self.pos_embed, std=0.02)
        nn.init.trunc_normal_(self.cls_token, std=0.02)
        for m in self.modules():
            if isinstance(m, nn.Linear):
                nn.init.trunc_normal_(m.weight, std=0.02)
                if m.bias is not None:
                    nn.init.zeros_(m.bias)
            elif isinstance(m, nn.LayerNorm):
                nn.init.ones_(m.weight)
                nn.init.zeros_(m.bias)

    def forward(self, x: torch.Tensor) -> dict[str, torch.Tensor]:
        B = x.size(0)
        x = self.patch_embed(x)                            # (B, N, D)
        cls = self.cls_token.expand(B, -1, -1)             # (B, 1, D)
        x = torch.cat([cls, x], dim=1)                     # (B, N+1, D)
        x = self.pos_drop(x + self.pos_embed)

        for blk in self.blocks:
            x = blk(x)

        x = self.norm(x)
        cls_feat = x[:, 0]                                 # CLS token
        return self.head(cls_feat)


def vit_small_patch16_224() -> ViT:
    return ViT(img_size=224, patch_size=16, dim=384, depth=12, num_heads=6)
