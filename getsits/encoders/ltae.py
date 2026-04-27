# Adapted from: https://github.com/VSainteuf/utae-paps

import copy

import numpy as np
import torch
import torch.nn as nn


class PositionalEncoder(nn.Module):
    def __init__(self, d, T=1000, repeat=None, offset=0):
        super(PositionalEncoder, self).__init__()
        self.d = d
        self.T = T
        self.repeat = repeat
        self.denom = torch.pow(
            T, 2 * (torch.arange(offset, offset + d).float() // 2) / d
        )
        self.updated_location = False

    def forward(self, batch_positions):
        if not self.updated_location:
            self.denom = self.denom.to(batch_positions.device)
            self.updated_location = True
        sinusoid_table = (
            batch_positions[:, :, None] / self.denom[None, None, :]
        )  # B x T x C
        sinusoid_table[:, :, 0::2] = torch.sin(sinusoid_table[:, :, 0::2])  # dim 2i
        sinusoid_table[:, :, 1::2] = torch.cos(sinusoid_table[:, :, 1::2])  # dim 2i+1

        if self.repeat is not None:
            sinusoid_table = torch.cat(
                [sinusoid_table for _ in range(self.repeat)], dim=-1
            )

        return sinusoid_table
    
class GeoTemporalEncoder(nn.Module):
    def __init__(self, embed_dim=256):
        super().__init__()
        self.time_dim = embed_dim // 2
        self.lat_dim = embed_dim // 4
        self.lon_dim = embed_dim // 4
        
        self.register_buffer('time_freqs', self._get_freqs(self.time_dim))
        self.register_buffer('lat_freqs', self._get_freqs(self.lat_dim))
        self.register_buffer('lon_freqs', self._get_freqs(self.lon_dim))

    def _get_freqs(self, dim):
        half_dim = dim // 2
        freqs = torch.exp(torch.arange(half_dim, dtype=torch.float32) * -(np.log(10000.0) / half_dim))
        return freqs

    def forward(self, doy, lat, lon):
        """
        doy: Tensor [B, T]
        lat: Tensor [B]
        lon: Tensor [B]
        """
        B, T = doy.shape
        
        doy_rad = doy * 2 * np.pi
        
        lat_rad = lat * (np.pi / 2)
        
        lon_rad = lon * np.pi
        
        lat_rad = lat_rad.unsqueeze(1).repeat(1, T) 
        lon_rad = lon_rad.unsqueeze(1).repeat(1, T) 
        
        def embed(inp, freqs):
            # inp: [B, T] -> [B, T, 1] * [1, 1, D/2] -> [B, T, D/2]
            args = inp.unsqueeze(-1) * freqs.view(1, 1, -1)
            return torch.cat([torch.sin(args), torch.cos(args)], dim=-1)

        t_emb = embed(doy_rad, self.time_freqs)
        l_emb = embed(lat_rad, self.lat_freqs)
        ln_emb = embed(lon_rad, self.lon_freqs)
        
        return torch.cat([t_emb, l_emb, ln_emb], dim=-1)

class LTAEChannelAdaptorOut(nn.Module):
    def __init__(self, in_channels: int, out_channels: list[int]) -> None:
        """LTAEChannelAdaptor for reducing channels progressively.

        Args:
            in_channels (int): Fixed number of input channels for all feature maps.
            out_channels (list[int]): Desired output channels for each feature map.
        """
        super(LTAEChannelAdaptorOut, self).__init__()
        assert isinstance(out_channels, list), "out_channels must be a list"
        
        # Create a 1x1 conv for each feature map, reducing its channels
        self.convs = nn.ModuleList(
            [
                nn.Conv2d(in_channels, out_c, kernel_size=1)
                for out_c in out_channels
            ]
        )

    def forward(self, features: list[torch.Tensor]) -> list[torch.Tensor]:
        """Adapt features from a fixed input channel size to different output sizes.

        Args:
            features (list[torch.Tensor]): List of feature maps (all with shape B, 512, H, W).

        Returns:
            list[torch.Tensor]: List of feature maps with adjusted channels.
        """
        assert len(features) == len(self.convs), (
            f"Expected {len(self.convs)} feature maps, but got {len(features)}."
        )
        
        return [conv(f) for conv, f in zip(self.convs, features)]


class LTAEChannelAdaptor(nn.Module):
    def __init__(self, in_channels: list[int], out_channels: list[int]) -> None:
        """LTAEChannelAdaptor for adapting the number of channels of the input features.

        Args:
            in_channels (list[int]): list of the number of input channels
            out_channels (list[int]): list of the number of output channels
        """
        super(LTAEChannelAdaptor, self).__init__()
        self.convs = nn.ModuleList(
            [
                nn.Conv2d(in_c, out_c, 1)
                for in_c, out_c in zip(in_channels, out_channels)
            ]
        )

    def forward(self, features: list[torch.Tensor]) -> list[torch.Tensor]:
        """Adapter for the number of channels of the input features.

        Args:
            features (list[torch.Tensor]): list of features of shape (B C T H W)
            from different layers of the encoder.

        Returns:
            list[torch.Tensor]: list of adapted features of shape (B C' T H W)
        """
        output = []
        for c, f in zip(self.convs, features):
            # for all frames
            adapted_feature = []
            # features of shape (B C T H W)
            for t in range(f.shape[-3]):
                adapted_feature.append(c(f[..., t, :, :]))

            output.append(torch.stack(adapted_feature, -3))
        return output


class LTAE2d(nn.Module):
    def __init__(
        self,
        in_channels=128,
        n_head=16,
        d_k=4,
        mlp=[256, 128],
        dropout=0.2,
        d_model=256,
        T=1000,
        return_att=False,
        positional_encoding="normal",
        layer_norm=False,
    ):
        """
        Lightweight Temporal Attention Encoder (L-TAE) for image time series.
        Attention-based sequence encoding that maps a sequence of images to a single feature map.
        A shared L-TAE is applied to all pixel positions of the image sequence.
        Args:
            in_channels (int): Number of channels of the input embeddings.
            n_head (int): Number of attention heads.
            d_k (int): Dimension of the key and query vectors.
            mlp (List[int]): Widths of the layers of the MLP that processes the concatenated outputs of the attention heads.
            dropout (float): dropout
            d_model (int, optional): If specified, the input tensors will first processed by a fully connected layer
                to project them into a feature space of dimension d_model.
            T (int): Period to use for the positional encoding.
            return_att (bool): If true, the module returns the attention masks along with the embeddings (default False)
            positional_encoding (bool): None, 'geotime', 'normal'.
        """
        super(LTAE2d, self).__init__()
        self.in_channels = in_channels
        self.mlp = copy.deepcopy(mlp)
        self.return_att = return_att
        self.n_head = n_head
        self.positional_encoding = positional_encoding

        if d_model is not None:
            self.d_model = d_model
            self.inconv = nn.Conv1d(in_channels, d_model, 1)
        else:
            self.d_model = in_channels
            self.inconv = None
        assert self.mlp[0] == self.d_model

        if positional_encoding == "normal":
            self.positional_encoder = PositionalEncoder(
                self.d_model // n_head, T=T, repeat=n_head
            )
        elif positional_encoding == "geotime":
            self.positional_encoder = GeoTemporalEncoder(self.d_model)
        else:
            self.positional_encoder = None

        self.attention_heads = MultiHeadAttention(
            n_head=n_head, d_k=d_k, d_in=self.d_model
        )
        self.in_norm = nn.GroupNorm(
            num_groups=n_head,
            num_channels=self.in_channels,
        )
        self.out_norm = nn.GroupNorm(
            num_groups=n_head,
            num_channels=mlp[-1],
        )

        layers = []
        
        for i in range(len(self.mlp) - 1):
            if not layer_norm:
                layers.extend(
                    [
                        nn.Linear(self.mlp[i], self.mlp[i + 1]),
                        nn.BatchNorm1d(self.mlp[i + 1]),
                        nn.ReLU(),
                    ]
                )
            else:
                layers.extend(
                    [
                        nn.Linear(self.mlp[i], self.mlp[i + 1]),
                        nn.LayerNorm(normalized_shape=self.mlp[i + 1]),
                        nn.GELU(),
                    ]
                )

        self.mlp = nn.Sequential(*layers)
        self.dropout = nn.Dropout(dropout)

    def forward(self, x, batch_positions=None, pad_mask=None, return_comp=False):
        sz_b, d, seq_len, h, w = x.shape
        x = x.permute(0, 2, 1, 3, 4)
        if pad_mask is not None:
            pad_mask = (
                pad_mask.unsqueeze(-1)
                .repeat((1, 1, h))
                .unsqueeze(-1)
                .repeat((1, 1, 1, w))
            )  # BxTxHxW
            pad_mask = (
                pad_mask.permute(0, 2, 3, 1).contiguous().view(sz_b * h * w, seq_len)
            )

        out = x.permute(0, 3, 4, 1, 2).contiguous().view(sz_b * h * w, seq_len, d)
        out = self.in_norm(out.permute(0, 2, 1)).permute(0, 2, 1)

        if self.inconv is not None:
            out = self.inconv(out.permute(0, 2, 1)).permute(0, 2, 1)

        if self.positional_encoding == "normal":
            bp = (
                batch_positions["time_linear"].unsqueeze(-1)
                .repeat((1, 1, h))
                .unsqueeze(-1)
                .repeat((1, 1, 1, w))
            )  # BxTxHxW
            bp = bp.permute(0, 2, 3, 1).contiguous().view(sz_b * h * w, seq_len)
            out = out + self.positional_encoder(bp.to(out.device))
        elif self.positional_encoding == "geotime":
            doy = batch_positions["doy"]
            lat = batch_positions["lat"]
            lon = batch_positions["lon"]

            doy_pixel = doy.unsqueeze(-1).unsqueeze(-1).expand(-1, -1, h, w)
            doy_pixel = doy_pixel.permute(0, 2, 3, 1).reshape(sz_b * h * w, seq_len)
            
            lat_pixel = lat.view(sz_b, 1, 1).expand(-1, h, w).reshape(sz_b * h * w)
            lon_pixel = lon.view(sz_b, 1, 1).expand(-1, h, w).reshape(sz_b * h * w)
            
            pe = self.positional_encoder(
                doy_pixel.to(out.device), 
                lat_pixel.to(out.device), 
                lon_pixel.to(out.device)
            )
            out = out + pe

        out, attn = self.attention_heads(out, pad_mask=pad_mask)

        out = (
            out.permute(1, 0, 2).contiguous().view(sz_b * h * w, -1)
        )  # Concatenate heads
        out = self.dropout(self.mlp(out))
        out = self.out_norm(out) if self.out_norm is not None else out
        out = out.view(sz_b, h, w, -1).permute(0, 3, 1, 2)

        attn = (
            attn.view(self.n_head, sz_b, h, w, seq_len)
            .permute(0, 1, 4, 2, 3)
            .contiguous()
        )  # head x b x t x h x w

        if self.return_att:
            return out, attn
        else:
            return out


class MultiHeadAttention(nn.Module):
    """Multi-Head Attention module
    Modified from github.com/jadore801120/attention-is-all-you-need-pytorch
    """

    def __init__(self, n_head, d_k, d_in):
        super().__init__()
        self.n_head = n_head
        self.d_k = d_k
        self.d_in = d_in

        self.Q = nn.Parameter(torch.zeros((n_head, d_k))).requires_grad_(True)
        nn.init.normal_(self.Q, mean=0, std=np.sqrt(2.0 / (d_k)))

        self.fc1_k = nn.Linear(d_in, n_head * d_k)
        nn.init.normal_(self.fc1_k.weight, mean=0, std=np.sqrt(2.0 / (d_k)))

        self.attention = ScaledDotProductAttention(temperature=np.power(d_k, 0.5))

    def forward(self, v, pad_mask=None, return_comp=False):
        d_k, d_in, n_head = self.d_k, self.d_in, self.n_head
        sz_b, seq_len, _ = v.size()

        q = torch.stack([self.Q for _ in range(sz_b)], dim=1).view(
            -1, d_k
        )  # (n*b) x d_k

        k = self.fc1_k(v).view(sz_b, seq_len, n_head, d_k)
        k = k.permute(2, 0, 1, 3).contiguous().view(-1, seq_len, d_k)  # (n*b) x lk x dk

        if pad_mask is not None:
            pad_mask = pad_mask.repeat(
                (n_head, 1)
            )  # replicate pad_mask for each head (nxb) x lk

        v = torch.stack(v.split(v.shape[-1] // n_head, dim=-1)).view(
            n_head * sz_b, seq_len, -1
        )
        if return_comp:
            output, attn, comp = self.attention(
                q, k, v, pad_mask=pad_mask, return_comp=return_comp
            )
        else:
            output, attn = self.attention(
                q, k, v, pad_mask=pad_mask, return_comp=return_comp
            )
        attn = attn.view(n_head, sz_b, 1, seq_len)
        attn = attn.squeeze(dim=2)

        output = output.view(n_head, sz_b, 1, d_in // n_head)
        output = output.squeeze(dim=2)

        if return_comp:
            return output, attn, comp
        else:
            return output, attn


class ScaledDotProductAttention(nn.Module):
    """Scaled Dot-Product Attention
    Modified from github.com/jadore801120/attention-is-all-you-need-pytorch
    """

    def __init__(self, temperature, attn_dropout=0.1):
        super().__init__()
        self.temperature = temperature
        self.dropout = nn.Dropout(attn_dropout)
        self.softmax = nn.Softmax(dim=2)

    def forward(self, q, k, v, pad_mask=None, return_comp=False):
        attn = torch.matmul(q.unsqueeze(1), k.transpose(1, 2))
        attn = attn / self.temperature
        if pad_mask is not None:
            attn = attn.masked_fill(pad_mask.unsqueeze(1), -1e3)
        if return_comp:
            comp = attn
        # compat = attn
        attn = self.softmax(attn)
        attn = self.dropout(attn)
        output = torch.matmul(attn, v)

        if return_comp:
            return output, attn, comp
        else:
            return output, attn
