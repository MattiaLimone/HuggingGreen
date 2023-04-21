from torch import nn
from hvit.classification_block.classification_head import ClassificationHead
from hvit.decision_block.patch_embedding import PatchEmbedding
from hvit.transformer_block.vit_transformer_encoder_block import TransformerEncoder


class ViT(nn.Sequential):
    def __init__(self,
                 in_channels: int = 3,
                 patch_size: int = 16,
                 emb_size: int = 768,
                 img_size: int = 224,
                 depth: int = 12,
                 num_heads: int = 12,
                 n_classes: int = 1000,
                 **kwargs):
        super().__init__(
            PatchEmbedding(in_channels, patch_size, emb_size, img_size),
            TransformerEncoder(depth, emb_size=emb_size, num_heads=num_heads, **kwargs),
            ClassificationHead(emb_size, n_classes)
        )
