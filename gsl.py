import torch
import torch.nn as nn
import torch.nn.functional as F


# A = ReLu(W)
class Graph_ReLu_W(nn.Module):
    def __init__(self, n_nodes, k, device):
        super(Graph_ReLu_W, self).__init__()
        self.k = k
        self.A = nn.Parameter(torch.randn(n_nodes, n_nodes))

    def forward(self, idx):
        adj = F.relu(self.A)
        if self.k is not None:
            mask = torch.zeros(idx.size(0), idx.size(0),
                               device=adj.device, dtype=adj.dtype)

            if self.training:
                noise = torch.rand_like(adj) * 0.01
                val_to_topk = adj + noise
            else:
                val_to_topk = adj

            v, id = val_to_topk.topk(self.k, 1)
            mask.scatter_(1, id, torch.ones_like(v))
            adj = adj * mask
        return adj


# A for Directed graphs:
class Graph_Directed_A(nn.Module):
    def __init__(self, n_nodes, window_size, alpha, k, device):
        super(Graph_Directed_A, self).__init__()
        self.alpha = alpha
        self.k = k
        self.device = device
        self.e1 = nn.Embedding(n_nodes, window_size)
        self.e2 = nn.Embedding(n_nodes, window_size)
        self.l1 = nn.Linear(window_size, window_size)
        self.l2 = nn.Linear(window_size, window_size)

    def forward(self, idx):
        m1 = torch.tanh(self.alpha*self.l1(self.e1(idx)))
        m2 = torch.tanh(self.alpha*self.l2(self.e2(idx)))
        adj = F.relu(torch.tanh(self.alpha*torch.mm(m1, m2.transpose(1, 0))))
        if self.k:
            mask = torch.zeros(idx.size(0), idx.size(0)).to(self.device)
            mask.fill_(float('0'))
            v, id = (adj + torch.rand_like(adj)*0.01).topk(self.k, 1)
            mask.scatter_(1, id, v.fill_(1))
            adj = adj*mask
        return adj


# A for Uni-directed graphs:
class Graph_Uni_Directed_A(nn.Module):
    def __init__(self, n_nodes, window_size, alpha, k, device):
        super(Graph_Directed_A, self).__init__()
        self.alpha = alpha
        self.k = k
        self.device = device
        self.e1 = nn.Embedding(n_nodes, window_size)
        self.e2 = nn.Embedding(n_nodes, window_size)
        self.l1 = nn.Linear(window_size, window_size)
        self.l2 = nn.Linear(window_size, window_size)

    def forward(self, idx):
        m1 = torch.tanh(self.alpha*self.l1(self.e1(idx)))
        m2 = torch.tanh(self.alpha*self.l2(self.e2(idx)))
        adj = F.relu(torch.tanh(self.alpha*(torch.mm(m1, m2.transpose(1, 0))
                                - torch.mm(m2, m1.transpose(1, 0)))))
        if self.k:
            mask = torch.zeros(idx.size(0), idx.size(0)).to(self.device)
            mask.fill_(float('0'))
            v, id = (adj + torch.rand_like(adj)*0.01).topk(self.k, 1)
            mask.scatter_(1, id, v.fill_(1))
            adj = adj*mask
        return adj


# A for Undirected graphs:
class Graph_Undirected_A(nn.Module):
    def __init__(self, n_nodes, window_size, alpha, k, device):
        super(Graph_Directed_A, self).__init__()
        self.alpha = alpha
        self.k = k
        self.device = device
        self.e1 = nn.Embedding(n_nodes, window_size)
        self.l1 = nn.Linear(window_size, window_size)

    def forward(self, idx):
        m1 = torch.tanh(self.alpha*self.l1(self.e1(idx)))
        m2 = torch.tanh(self.alpha*self.l1(self.e1(idx)))
        adj = F.relu(torch.tanh(self.alpha*torch.mm(m1, m2.transpose(1, 0))))
        if self.k:
            mask = torch.zeros(idx.size(0), idx.size(0)).to(self.device)
            mask.fill_(float('0'))
            v, id = (adj + torch.rand_like(adj)*0.01).topk(self.k, 1)
            mask.scatter_(1, id, v.fill_(1))
            adj = adj*mask
        return adj

class Graph_Tanh_W(nn.Module):
    def __init__(self, n_nodes, alpha, k, device):
        super(Graph_Tanh_W, self).__init__()
        self.alpha = alpha
        self.k = k
        self.A = nn.Parameter(torch.randn(n_nodes, n_nodes))

    def forward(self, idx):
        adj = torch.tanh(self.alpha * self.A)
        if self.k is not None:
            mask = torch.zeros(idx.size(0), idx.size(0),
                               device=adj.device, dtype=adj.dtype)
            if self.training:
                noise = torch.rand_like(adj) * 0.01
                val_to_topk = adj.abs() + noise
            else:
                val_to_topk = adj.abs()
            _, id = val_to_topk.topk(self.k, 1)
            mask.scatter_(1, id, torch.ones(idx.size(0), self.k,
                                            device=adj.device, dtype=adj.dtype))
            adj = adj * mask
        return adj

class GSL(nn.Module):
    def __init__(self, gsl_type, n_nodes, window_size, alpha, k, device):
        super(GSL, self).__init__()
        self.gsl_layer = None
        if gsl_type == 'relu':
            self.gsl_layer = Graph_ReLu_W(n_nodes, k, device)
        elif gsl_type == 'tanh':
            self.gsl_layer = Graph_Tanh_W(n_nodes, alpha, k, device)
        elif gsl_type == 'directed':
            self.gsl_layer = Graph_Directed_A(n_nodes, window_size, alpha, k, device)
        elif gsl_type == 'unidirected':
            self.gsl_layer = Graph_Uni_Directed_A(n_nodes, window_size, alpha, k, device)
        elif gsl_type == 'undirected':
            self.gsl_layer = Graph_Undirected_A(n_nodes, window_size, alpha, k, device)
        else:
            raise ValueError(f'Unknown GSL type: {gsl_type}')

    def forward(self, idx):
        return self.gsl_layer(idx)