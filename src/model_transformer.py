import paddle
import paddle.nn as nn

from src.encoder_ms import Encoder, EncoderLayer, ConvLayer
from src.decoder_ms import Decoder, DecoderLayer
from src.attn_ms import FullAttention, ProbAttention, AttentionLayer
from src.embed_ms import DataEmbedding


class Informer(nn.Layer):
    def __init__(self, enc_in, dec_in, c_out, pred_len,
                 factor=5, d_model=256, n_heads=4, e_layers=2, d_layers=1, d_ff=128,
                 dropout=0.0, attn='full', activation='gelu',
                 output_attention=False, distil=True,
                 mix=True):
        super(Informer, self).__init__()
        self.pred_len = pred_len
        self.attn = attn
        self.output_attention = output_attention

        # Encoding
        self.enc_embedding = DataEmbedding(enc_in, d_model, dropout)
        self.dec_embedding = DataEmbedding(dec_in, d_model, dropout)
        # Attention
        Attn = ProbAttention if attn == 'prob' else FullAttention
        # Encoder
        self.encoder = Encoder(
            [
                EncoderLayer(
                    AttentionLayer(Attn(False, factor, attention_dropout=dropout, output_attention=output_attention),
                                   d_model, n_heads, mix=False),
                    d_model,
                    d_ff,
                    dropout=dropout,
                    activation=activation
                ) for l in range(e_layers)
            ],
            [
                ConvLayer(
                    d_model
                ) for l in range(e_layers - 1)
            ] if distil else None,
            norm_layer=nn.LayerNorm([d_model])
        )
        # Decoder
        self.decoder = Decoder(
            [
                DecoderLayer(
                    AttentionLayer(Attn(True, factor, attention_dropout=dropout, output_attention=False),
                                   d_model, n_heads, mix=mix),
                    AttentionLayer(FullAttention(False, factor, attention_dropout=dropout, output_attention=False),
                                   d_model, n_heads, mix=False),
                    d_model,
                    d_ff,
                    dropout=dropout,
                    activation=activation,
                )
                for l in range(d_layers)
            ],
            norm_layer=nn.LayerNorm([d_model])
        )
        # Projection
        self.projection = nn.Linear(d_model, c_out)

    def forward(self, x_enc, x_dec, enc_self_mask=None, dec_self_mask=None, dec_enc_mask=None):
        enc_out = self.enc_embedding(x_enc)
        print(f"Shape of enc_out after enc_embedding: {enc_out.shape}")
        enc_out, _ = self.encoder(enc_out, attn_mask=enc_self_mask)
        print(f"Shape of enc_out after encoder: {enc_out.shape}")
        dec_out = self.dec_embedding(x_dec)
        print(f"Shape of dec_out after dec_embedding: {dec_out.shape}")
        dec_out = self.decoder(dec_out, enc_out, x_mask=dec_self_mask, cross_mask=dec_enc_mask)
        print(f"Shape of dec_out after decoder: {dec_out.shape}")
        dec_out = self.projection(dec_out)
        print(f"Shape of dec_out after projection: {dec_out.shape}")

        return dec_out[:, -self.pred_len:, :]  # [B, L, D]



