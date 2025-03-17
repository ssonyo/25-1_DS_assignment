import torch
import torch.nn as nn
from typing import Optional
from .attention import MultiHeadAttention
from .feedforward import FeedForwardLayer, DropoutLayer
from .normalization import LayerNormalization
from .residual import ResidualConnection


class TransformerDecoderLayer(nn.Module):
    def __init__(self, d_model: int, n_heads: int, d_ff: int, dropout: float) -> None:
        super(TransformerDecoderLayer, self).__init__()
        
        self.self_attn = MultiHeadAttention(d_model, n_heads)
        self.cross_attn = MultiHeadAttention(d_model, n_heads)
        self.feed_forward = FeedForwardLayer(d_model, d_ff)
        
        self.norm1 = LayerNormalization(d_model)
        self.norm2 = LayerNormalization(d_model)
        self.norm3 = LayerNormalization(d_model)
        
        self.dropout1 = DropoutLayer(dropout)
        self.dropout2 = DropoutLayer(dropout)
        self.dropout3 = DropoutLayer(dropout)
        
        self.residual1 = ResidualConnection()
        self.residual2 = ResidualConnection()
        self.residual3 = ResidualConnection()
    
    def forward(self, 
                x: torch.Tensor, 
                memory: torch.Tensor, 
                src_mask: Optional[torch.Tensor] = None, 
                tgt_mask: Optional[torch.Tensor] = None) -> torch.Tensor:
        #TODO

        # Self-attention
        self_attn_out = self.self_attn(x, x, x, mask=tgt_mask)
        x = self.residual1(x, self.dropout1(self_attn_out))
        x = self.norm1(x)
        
        # Cross-attention with encoder output
        cross_attn_out = self.cross_attn(x, memory, memory, mask=src_mask)
        x = self.residual2(x, self.dropout2(cross_attn_out))
        x = self.norm2(x)
        
        # Feed-forward network
        ff_out = self.feed_forward(x)
        x = self.residual3(x, self.dropout3(ff_out))
        x = self.norm3(x)
        
        return x