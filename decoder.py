import torch.nn as nn

from multi_head_attention import MultiHeadAttention
from layer_normalization import LayerNormalization
from multi_head_cross_attention import MultiHeadCrossAttention
from positionwise_feedforward import PositionwiseFeedForward

class DecoderLayer(nn.Module):
  def __init__(self, d_model, ffn_hidden, num_heads, drop_prob):
    super(DecoderLayer, self).__init__()
    self.self_attention = MultiHeadAttention(d_model=d_model, num_heads=num_heads)
    self.norm1 = LayerNormalization(parameters_shape=[d_model])
    self.dropout1 = nn.Dropout(p=drop_prob)
    self.encoder_decoder_attention = MultiHeadCrossAttention(d_model=d_model, num_heads=num_heads)
    self.norm2 = LayerNormalization(parameters_shape=[d_model])
    self.dropout2 = nn.Dropout(p=drop_prob)
    self.ffn = PositionwiseFeedForward(d_model=d_model, ffn_hidden=ffn_hidden, drop_prob=drop_prob)
    self.norm3 = LayerNormalization(parameters_shape=[d_model])
    self.dropout3 = nn.Dropout(p=drop_prob)

  def forward(self, x, y, decoder_mask):
    _y = y
    y = self.self_attention(y, mask=decoder_mask)
    y = self.dropout1(y)
    y = self.norm1(y + _y)

    _y = y
    y = self.encoder_decoder_attention(x, y, mask=None)
    y = self.dropout2(y)
    y = self.norm2(y + _y)

    _y = y
    y = self.ffn(y)
    y = self.dropout3(y)
    y = self.norm3(y + _y)
    return y

class SequentialDecoder(nn.Sequential):
  def forward(self, *inputs):
    x, y, mask = inputs
    for module in self._modules.values():
      y = module(x, y, mask)
    return y

class Decoder(nn.Module):
  def __init__(self, d_model, ffn_hidden, num_heads, drop_prob, num_layers=1):
    super().__init__()
    self.layers = SequentialDecoder(*[DecoderLayer(d_model, ffn_hidden, num_heads, drop_prob) for _ in range(num_layers)])

  def forward(self, x, y, mask):
    return self.layers(x, y, mask)