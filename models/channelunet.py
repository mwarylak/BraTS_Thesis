import torch
import torch.nn.functional as F
from torch import nn

class EncoderBlock(nn.Module):
    def __init__(self, in_channels, out_channels, activation=nn.ReLU()):
        super().__init__()
        self.encoder_block = nn.Sequential(
            nn.Conv2d(in_channels,  out_channels, kernel_size=(3,3), stride=1, padding=1),
            nn.BatchNorm2d(out_channels),
            activation,
            nn.Conv2d(out_channels, out_channels, kernel_size=(3,3), stride=1, padding=1),
            nn.BatchNorm2d(out_channels),
            activation
        )
    def forward(self, x):
        return self.encoder_block(x)

class DecoderBlock(nn.Module):
    def __init__(self, in_channels, out_channels, activation=nn.ReLU()):
        super().__init__()
        self.decoder_block = nn.Sequential(
            nn.Conv2d(in_channels,  in_channels//2, kernel_size=(3,3), stride=1, padding=1),
            nn.BatchNorm2d(in_channels//2),
            activation,
            nn.Conv2d(in_channels//2, out_channels, kernel_size=(3,3), stride=1, padding=1),
            nn.BatchNorm2d(out_channels),
            activation
        )
    def forward(self, x):
        return self.decoder_block(x)

class AttentionResBlock(nn.Module):
    def __init__(self, in_channels, activation=nn.ReLU()):
        super().__init__()
        self.query_conv     = nn.Conv2d(in_channels, in_channels, kernel_size=(1,1), stride=1)
        self.key_conv       = nn.Conv2d(in_channels, in_channels, kernel_size=(1,1), stride=2)
        self.attention_conv = nn.Conv2d(in_channels, 1, kernel_size=(1,1), stride=1)

        self.upsample       = nn.UpsamplingBilinear2d(scale_factor=2)
        self.activation     = activation

    def forward(self, query, key, value):
        query = self.query_conv(query)
        key   = self.key_conv(key)

        combined_attention = self.activation(query + key)
        attention_map = torch.sigmoid(self.attention_conv(combined_attention))
        upsampled_attention_map = self.upsample(attention_map)
        attention_scores = value * upsampled_attention_map
        return attention_scores

class SE_Block(nn.Module):
    def __init__(self, in_channels, reduction=16, activation=nn.ReLU()):
        super(SE_Block, self).__init__()
        self.fc1 = nn.Conv2d(in_channels, in_channels // reduction, kernel_size=1)
        self.fc2 = nn.Conv2d(in_channels // reduction, in_channels, kernel_size=1)
        self.sigmoid = nn.Sigmoid()
        self.activation = activation

    def forward(self, x):
        # Squeeze operation (Global Average Pooling)
        avg_pool = torch.mean(x, dim=[2, 3], keepdim=True)  # (B, C, 1, 1)
        # Excitation operation
        excitation = self.fc1(avg_pool)
        excitation = self.activation(excitation)
        excitation = self.fc2(excitation)
        excitation = self.sigmoid(excitation)

        # Apply attention
        return x * excitation

class AttentionUNet(nn.Module):
    def __init__(self, activation_fun):
        super().__init__()

        # Config
        in_channels  = 4   # Input images have 4 channels
        out_channels = 3   # Mask has 3 channels
        n_filters    = 32  # Scaled down from 64 in original paper
        activation   = nn.ReLU()
        if activation_fun == 'LeakyReLU':
          activation = nn.LeakyReLU(negative_slope=0.1)
          print('Activation: Leaky ReLU')
        else:
            print('Activation: ReLU')

        # Up and downsampling methods
        self.downsample  = nn.MaxPool2d((2,2), stride=2)
        self.upsample    = nn.UpsamplingBilinear2d(scale_factor=2)

        # Encoder
        self.enc_block_1 = EncoderBlock(in_channels, 1*n_filters, activation)
        self.enc_block_2 = EncoderBlock(1*n_filters, 2*n_filters, activation)
        self.enc_block_3 = EncoderBlock(2*n_filters, 4*n_filters, activation)
        self.enc_block_4 = EncoderBlock(4*n_filters, 8*n_filters, activation)

        # Bottleneck
        self.bottleneck  = nn.Sequential(
            nn.Conv2d(8*n_filters, 16*n_filters, kernel_size=(3,3), stride=1, padding=1),
            nn.BatchNorm2d(16*n_filters),
            activation,
            nn.Conv2d(16*n_filters,  8*n_filters, kernel_size=(3,3), stride=1, padding=1),
            nn.BatchNorm2d(8*n_filters),
            activation
        )

        # Decoder
        self.dec_block_4 = DecoderBlock(16*n_filters, 4*n_filters, activation)
        self.dec_block_3 = DecoderBlock(8*n_filters, 2*n_filters, activation)
        self.dec_block_2 = DecoderBlock(4*n_filters, 1*n_filters, activation)
        self.dec_block_1 = DecoderBlock(2*n_filters, 1*n_filters, activation)

        # Output projection
        self.output      = nn.Conv2d(1*n_filters,  out_channels, kernel_size=(1,1), stride=1, padding=0)

        self.att_res_block_1 = AttentionResBlock(1*n_filters)
        self.att_res_block_2 = AttentionResBlock(2*n_filters)
        self.att_res_block_3 = AttentionResBlock(4*n_filters)
        self.att_res_block_4 = AttentionResBlock(8*n_filters)

         # Channel Attention Block (Kanałowa uwaga)
        self.channel_att_1 = SE_Block(2*n_filters)
        self.channel_att_2 = SE_Block(4*n_filters)
        self.channel_att_3 = SE_Block(8*n_filters)
        self.channel_att_4 = SE_Block(16*n_filters)

    def forward(self, x):
            enc_1 = self.enc_block_1(x)
            x     = self.downsample(enc_1)
            enc_2 = self.enc_block_2(x)
            x     = self.downsample(enc_2)
            enc_3 = self.enc_block_3(x)
            x     = self.downsample(enc_3)
            enc_4 = self.enc_block_4(x)
            x     = self.downsample(enc_4)

            # Bottleneck
            dec_4 = self.bottleneck(x)

            # Decoder
            x     = self.upsample(dec_4)
            att_4 = self.att_res_block_4(dec_4, enc_4, enc_4)  # QKV
            x     = torch.cat((x, att_4), axis=1)  # Add attention masked value rather than concat
            x     = self.channel_att_4(x)

            dec_3 = self.dec_block_4(x)
            x     = self.upsample(dec_3)
            att_3 = self.att_res_block_3(dec_3, enc_3, enc_3)
            x     = torch.cat((x, att_3), axis=1)  # Add attention
            x     = self.channel_att_3(x)

            dec_2 = self.dec_block_3(x)
            x     = self.upsample(dec_2)
            att_2 = self.att_res_block_2(dec_2, enc_2, enc_2)
            x     = torch.cat((x, att_2), axis=1)  # Add attention
            x     = self.channel_att_2(x)

            dec_1 = self.dec_block_2(x)
            x     = self.upsample(dec_1)
            att_1 = self.att_res_block_1(dec_1, enc_1, enc_1)
            x     = torch.cat((x, att_1), axis=1)  # Add attention
            x     = self.channel_att_1(x)

            x     = self.dec_block_1(x)
            x     = self.output(x)
            return x