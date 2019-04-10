import torch, torch.nn as nn, torch.nn.functional as F
import torch.nn.init as init
# from models.Modules import BottleLinear as Linear
from models.Modules import XavierLinear as Linear
from models.Modules import ScaledDotProductAttention
from pdb import set_trace as stop
import numpy as np


class MultiHeadAttention(nn.Module):
    def __init__(self, n_head, d_model, d_k, d_v, dropout=0.1, dropout2=False,attn_type='softmax'):
        super().__init__()

        self.n_head = n_head
        self.d_k = d_k
        self.d_v = d_v

        self.w_qs = nn.Linear(d_model, n_head * d_k,bias=False)
        self.w_ks = nn.Linear(d_model, n_head * d_k,bias=False)
        self.w_vs = nn.Linear(d_model, n_head * d_v,bias=False)
        nn.init.normal_(self.w_qs.weight, mean=0, std=np.sqrt(2.0 / (d_model + d_k)))
        nn.init.normal_(self.w_ks.weight, mean=0, std=np.sqrt(2.0 / (d_model + d_k)))
        nn.init.normal_(self.w_vs.weight, mean=0, std=np.sqrt(2.0 / (d_model + d_v)))

        if dropout2:
            # self.dropout2 = nn.Dropout(dropout2)
            self.attention = ScaledDotProductAttention(temperature=np.power(d_k, 0.5), attn_type=attn_type,dropout=dropout2)
        else:
            self.attention = ScaledDotProductAttention(temperature=np.power(d_k, 0.5),attn_type=attn_type,dropout=dropout)
        
        self.dropout = nn.Dropout(dropout)
        

        self.layer_norm = nn.LayerNorm(d_model)

        if n_head > 1:
            self.fc = nn.Linear(n_head * d_v, d_model,bias=False)
            nn.init.xavier_normal_(self.fc.weight)


    def forward(self, q, k, v, attn_mask=None,dec_self=False): 

        d_k, d_v, n_head = self.d_k, self.d_v, self.n_head

        sz_b, len_q, _ = q.size()
        sz_b, len_k, _ = k.size()
        sz_b, len_v, _ = v.size()

        residual = q
        
        if hasattr(self,'dropout2'):
            # ones = torch.ones(q.size(0),q.size(1))
            # ones = self.dropout2(ones)
            # ones = ones.unsqueeze(2).repeat(1,1,q.size(2)).cuda()
            # q = ones*q
            q = self.dropout2(q)

        
        q = self.w_qs(q).view(sz_b, len_q, n_head, d_k)
        k = self.w_ks(k).view(sz_b, len_k, n_head, d_k)
        v = self.w_vs(v).view(sz_b, len_v, n_head, d_v)


        q = q.permute(2, 0, 1, 3).contiguous().view(-1, len_q, d_k) # (n*b) x lq x dk
        k = k.permute(2, 0, 1, 3).contiguous().view(-1, len_k, d_k) # (n*b) x lk x dk
        v = v.permute(2, 0, 1, 3).contiguous().view(-1, len_v, d_v) # (n*b) x lv x dv


        if attn_mask is not None:
            attn_mask = attn_mask.repeat(n_head, 1, 1) # (n*b) x .. x ..

        output, attn = self.attention(q, k, v, attn_mask=attn_mask)

        output = output.view(n_head, sz_b, len_q, d_v)
        output = output.permute(1, 2, 0, 3).contiguous().view(sz_b, len_q, -1) # b x lq x (n*dv)

        if hasattr(self,'fc'):
            output = self.fc(output)

        if hasattr(self,'dropout'):
            output = self.dropout(output)
        

        if dec_self:
            # stop()
            # output = output*(F.dropout(torch.ones(output.size(0)).cuda(),0.5)/2).view(-1,1,1).repeat(1,output.size(1),output.size(2))
            output = self.layer_norm(output + residual)
        else:
            output = self.layer_norm(output + residual)

        return output, attn



class PositionwiseFeedForward(nn.Module):
    def __init__(self, d_in, d_hid, dropout=0.1):
        super().__init__()
        self.w_1 = nn.Conv1d(d_in, d_hid, 1) # position-wise
        self.w_2 = nn.Conv1d(d_hid, d_in, 1) # position-wise
        self.layer_norm = nn.LayerNorm(d_in)
        self.dropout = nn.Dropout(dropout)

    def forward(self, x):
        residual = x
        output = x.transpose(1, 2)
        output = self.w_2(F.relu(self.w_1(output)))
        output = output.transpose(1, 2)
        output = self.dropout(output)

        
        output = self.layer_norm(output + residual)
        # output = (output + residual)
        # output = self.layer_norm(output)
        return output









