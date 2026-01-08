# -*- coding: utf-8 -*-

import torch
from torch._C import dtype
import torch.nn as nn
import torch.nn.functional as F
from torch.distributions.uniform import Uniform
from torch.nn.functional import conv2d
from torch.nn.common_types import _size_2_t
from torch.nn.modules.utils import _pair
import numpy as np
import math
from torch.nn.functional import leaky_relu, relu
import matplotlib.pyplot as plt


class MLP(nn.Module):
    def __init__(self, D, d, last_relu=False):
        super(MLP, self).__init__()

        self.model = nn.Sequential()
        self.model.add_module("fc1", nn.Linear(D, 300))
        self.model.add_module("act1", nn.LeakyReLU())
        self.model.add_module("fc2", nn.Linear(300, 200))
        self.model.add_module("act2", nn.LeakyReLU())
        self.model.add_module("fc3", nn.Linear(200, d))
        if last_relu:
            self.model.add_module("act3", nn.LeakyReLU())

    def forward(self, data):
        out = self.model(data)

        return out


def make_mlp(dim_list, activation="relu", batch_norm=True, dropout=0):
    layers = []
    for dim_in, dim_out in zip(dim_list[:-1], dim_list[1:]):
        layers.append(nn.Linear(dim_in, dim_out))
        if batch_norm:
            layers.append(nn.BatchNorm1d(dim_out))
        if activation == "relu":
            layers.append(nn.ReLU())
        elif activation == "leakyrelu":
            layers.append(nn.LeakyReLU())
        if dropout > 0:
            layers.append(nn.Dropout(p=dropout))
    return nn.Sequential(*layers)


class GCLayer(nn.Module):
    def __init__(self, d, D, device="cpu"):
        super(GCLayer, self).__init__()
        self.d = d
        self.D = D
        self.device = device
        self.W = nn.Parameter(torch.randn(d, D))

    def to(self, device):
        super().to(device)
        self.device = device

    def forward(self, X, A):
        X_gc = torch.matmul(A, X)

        gc = torch.matmul(X_gc, self.W)
        out = relu(gc)
        return out


class GraphAttentionLayer(nn.Module):
    def __init__(
        self,
        in_features,
        out_features,
        n_heads=8,
        dropout_rate=0.0,
        alpha=0.2,
        concat=True,
        share_weights=False,
    ):
        super(GraphAttentionLayer, self).__init__()
        self.in_features = in_features
        self.out_features = out_features
        self.n_heads = n_heads
        self.concat = concat

        if concat:
            assert out_features % n_heads == 0
            self.h_dim = out_features // n_heads
        else:
            self.h_dim = out_features

        self.linear_l = nn.Linear(in_features, self.h_dim * n_heads, bias=False)

        if share_weights:
            self.linear_r = self.linear_l
        else:
            self.linear_r = nn.Linear(in_features, self.h_dim * n_heads, bias=False)

        self.attn = nn.Linear(self.h_dim, 1, bias=False)
        self.activation = nn.LeakyReLU(negative_slope=alpha)
        self.softmax = nn.Softmax(dim=1)
        self.dropout = nn.Dropout(dropout_rate)

    def forward(self, h):
        n_batches = h.shape[0]
        n_nodes = h.shape[1]

        g_l = self.linear_l(h).view(n_batches, n_nodes, self.n_heads, self.h_dim)
        g_r = self.linear_r(h).view(n_batches, n_nodes, self.n_heads, self.h_dim)

        g_l_repeat = g_l.repeat(1, n_nodes, 1, 1)

        g_r_repeat_interleave = g_r.repeat_interleave(n_nodes, dim=1)

        g_sum = g_l_repeat + g_r_repeat_interleave

        g_sum = g_sum.view(n_batches, n_nodes, n_nodes, self.n_heads, self.h_dim)

        e = self.attn(self.activation(g_sum))

        e = e.squeeze(-1)

        a = self.softmax(e)

        a = self.dropout(a)

        attn_res = torch.einsum("bijh,bjhf->bihf", a, g_r)

        if self.concat:
            return attn_res.reshape(n_batches, n_nodes, self.n_heads * self.h_dim)
        else:
            return attn_res.mean(dim=1)
