"""The module.
"""
from typing import List
from needle.autograd import Tensor
from needle import ops
import needle.init as init
import numpy as np
from .nn_basic import Parameter, Module


class Sigmoid(Module):
    def __init__(self):
        super().__init__()

    def forward(self, x: Tensor) -> Tensor:
        return (1 + ops.exp(-x)) ** -1

class RNNCell(Module):
    def __init__(self, input_size, hidden_size, bias=True, nonlinearity='tanh', device=None, dtype="float32"):
        """
        Applies an RNN cell with tanh or ReLU nonlinearity.

        Parameters:
        input_size: The number of expected features in the input X
        hidden_size: The number of features in the hidden state h
        bias: If False, then the layer does not use bias weights
        nonlinearity: The non-linearity to use. Can be either 'tanh' or 'relu'.

        Variables:
        W_ih: The learnable input-hidden weights of shape (input_size, hidden_size).
        W_hh: The learnable hidden-hidden weights of shape (hidden_size, hidden_size).
        bias_ih: The learnable input-hidden bias of shape (hidden_size,).
        bias_hh: The learnable hidden-hidden bias of shape (hidden_size,).

        Weights and biases are initialized from U(-sqrt(k), sqrt(k)) where k = 1/hidden_size
        """
        super().__init__()
        self.bias = bias
        self.input_size = input_size
        self.hidden_size = hidden_size
        interval = 1 / (hidden_size ** 0.5)
        self.activation = ops.tanh if nonlinearity == 'tanh' else ops.relu
        self.W_ih = Parameter(init.rand(input_size, hidden_size, low=-interval, high=interval, device=device))
        self.W_hh = Parameter(init.rand(hidden_size, hidden_size, low=-interval, high=interval, device=device))
        if bias:
            self.bias_ih = Parameter(init.rand(hidden_size, low=-interval, high=interval, device=device))
            self.bias_hh = Parameter(init.rand(hidden_size, low=-interval, high=interval, device=device))

    def forward(self, X, h=None):
        """
        Inputs:
        X of shape (bs, input_size): Tensor containing input features
        h of shape (bs, hidden_size): Tensor containing the initial hidden state
            for each element in the batch. Defaults to zero if not provided.

        Outputs:
        h' of shape (bs, hidden_size): Tensor contianing the next hidden state
            for each element in the batch.
        """
        accum = X @ self.W_ih
        if h:
            accum += h @ self.W_hh
        if self.bias:
            accum += (self.bias_ih + self.bias_hh).reshape((1, self.hidden_size)).broadcast_to(accum.shape)
        return self.activation(accum)


class RNN(Module):
    def __init__(self, input_size, hidden_size, num_layers=1, bias=True, nonlinearity='tanh', device=None, dtype="float32"):
        """
        Applies a multi-layer RNN with tanh or ReLU non-linearity to an input sequence.

        Parameters:
        input_size - The number of expected features in the input x
        hidden_size - The number of features in the hidden state h
        num_layers - Number of recurrent layers.
        nonlinearity - The non-linearity to use. Can be either 'tanh' or 'relu'.
        bias - If False, then the layer does not use bias weights.

        Variables:
        rnn_cells[k].W_ih: The learnable input-hidden weights of the k-th layer,
            of shape (input_size, hidden_size) for k=0. Otherwise the shape is
            (hidden_size, hidden_size).
        rnn_cells[k].W_hh: The learnable hidden-hidden weights of the k-th layer,
            of shape (hidden_size, hidden_size).
        rnn_cells[k].bias_ih: The learnable input-hidden bias of the k-th layer,
            of shape (hidden_size,).
        rnn_cells[k].bias_hh: The learnable hidden-hidden bias of the k-th layer,
            of shape (hidden_size,).
        """
        super().__init__()
        self.layers = num_layers
        self.rnn_cells = [RNNCell(input_size if i == 0 else hidden_size, hidden_size, bias, nonlinearity, device) for i in range(num_layers)]

    def forward(self, X, h0=None):
        """
        Inputs:
        X of shape (seq_len, bs, input_size) containing the features of the input sequence.
        h_0 of shape (num_layers, bs, hidden_size) containing the initial
            hidden state for each element in the batch. Defaults to zeros if not provided.

        Outputs
        output of shape (seq_len, bs, hidden_size) containing the output features
            (h_t) from the last layer of the RNN, for each t.
        h_n of shape (num_layers, bs, hidden_size) containing the final hidden state for each element in the batch.
        """
        X_steps = ops.split(X, axis=0)
        seq_len = len(X_steps)
        bs = X_steps[0].shape[0]
        
        if h0 is None:
            h = [init.zeros(bs, self.rnn_cells[0].hidden_size, device=X.device, dtype=X.dtype) for _ in range(self.layers)]
        else:
            h = list(ops.split(h0, axis=0))
        
        outputs = []
        for t in range(seq_len):
            x_t = X_steps[t]
            for layer_idx in range(self.layers):
                x_t = self.rnn_cells[layer_idx](x_t, h[layer_idx])
                h[layer_idx] = x_t
            outputs.append(x_t)
        
        output = ops.stack(outputs, axis=0)
        h_n = ops.stack(h, axis=0)
        
        return output, h_n


class LSTMCell(Module):
    def __init__(self, input_size, hidden_size, bias=True, device=None, dtype="float32"):
        """
        A long short-term memory (LSTM) cell.

        Parameters:
        input_size - The number of expected features in the input X
        hidden_size - The number of features in the hidden state h
        bias - If False, then the layer does not use bias weights

        Variables:
        W_ih - The learnable input-hidden weights, of shape (input_size, 4*hidden_size).
        W_hh - The learnable hidden-hidden weights, of shape (hidden_size, 4*hidden_size).
        bias_ih - The learnable input-hidden bias, of shape (4*hidden_size,).
        bias_hh - The learnable hidden-hidden bias, of shape (4*hidden_size,).

        Weights and biases are initialized from U(-sqrt(k), sqrt(k)) where k = 1/hidden_size
        """
        super().__init__()
        self.bias = bias
        self.input_size = input_size
        self.hidden_size = hidden_size
        interval = 1 / (hidden_size ** 0.5)
        self.W_ih = Parameter(init.rand(input_size, 4*hidden_size, low=-interval, high=interval, device=device))
        self.W_hh = Parameter(init.rand(hidden_size, 4*hidden_size, low=-interval, high=interval, device=device))
        if bias:
            self.bias_ih = Parameter(init.rand(4*hidden_size, low=-interval, high=interval, device=device))
            self.bias_hh = Parameter(init.rand(4*hidden_size, low=-interval, high=interval, device=device)) 


    def forward(self, X, h=None):
        """
        Inputs: X, h
        X of shape (batch, input_size): Tensor containing input features
        h, tuple of (h0, c0), with
            h0 of shape (bs, hidden_size): Tensor containing the initial hidden state
                for each element in the batch. Defaults to zero if not provided.
            c0 of shape (bs, hidden_size): Tensor containing the initial cell state
                for each element in the batch. Defaults to zero if not provided.

        Outputs: (h', c')
        h' of shape (bs, hidden_size): Tensor containing the next hidden state for each
            element in the batch.
        c' of shape (bs, hidden_size): Tensor containing the next cell state for each
            element in the batch.
        """
        accum = X @ self.W_ih
        if h:
            h0, c0 = h
        else:
            h0 = init.zeros(X.shape[0], self.hidden_size, device=X.device)
            c0 = init.zeros(X.shape[0], self.hidden_size, device=X.device)
        accum += h0 @ self.W_hh
        if self.bias:
            accum += (self.bias_hh + self.bias_ih).reshape((1, 4 * self.hidden_size)).broadcast_to(accum.shape)
        gates = ops.split(accum.reshape((X.shape[0], 4, self.hidden_size)), axis = 1)
        i = Sigmoid()(gates[0])
        f = Sigmoid()(gates[1])
        g = ops.tanh((gates[2]))
        o = Sigmoid()(gates[3])
        
        cp = f * c0 + i * g
        hp = o * ops.tanh(cp)
        return hp, cp


class LSTM(Module):
    def __init__(self, input_size, hidden_size, num_layers=1, bias=True, device=None, dtype="float32"):
        super().__init__()
        """
        Applies a multi-layer long short-term memory (LSTM) RNN to an input sequence.

        Parameters:
        input_size - The number of expected features in the input x
        hidden_size - The number of features in the hidden state h
        num_layers - Number of recurrent layers.
        bias - If False, then the layer does not use bias weights.

        Variables:
        lstm_cells[k].W_ih: The learnable input-hidden weights of the k-th layer,
            of shape (input_size, 4*hidden_size) for k=0. Otherwise the shape is
            (hidden_size, 4*hidden_size).
        lstm_cells[k].W_hh: The learnable hidden-hidden weights of the k-th layer,
            of shape (hidden_size, 4*hidden_size).
        lstm_cells[k].bias_ih: The learnable input-hidden bias of the k-th layer,
            of shape (4*hidden_size,).
        lstm_cells[k].bias_hh: The learnable hidden-hidden bias of the k-th layer,
            of shape (4*hidden_size,).
        """
        self.layers = num_layers
        self.lstm_cells = [LSTMCell(input_size if k == 0 else hidden_size, hidden_size, bias, device=device) for k in range(num_layers)]

    def forward(self, X, h=None):
        """
        Inputs: X, h
        X of shape (seq_len, bs, input_size) containing the features of the input sequence.
        h, tuple of (h0, c0) with
            h_0 of shape (num_layers, bs, hidden_size) containing the initial
                hidden state for each element in the batch. Defaults to zeros if not provided.
            c0 of shape (num_layers, bs, hidden_size) containing the initial
                hidden cell state for each element in the batch. Defaults to zeros if not provided.

        Outputs: (output, (h_n, c_n))
        output of shape (seq_len, bs, hidden_size) containing the output features
            (h_t) from the last layer of the LSTM, for each t.
        tuple of (h_n, c_n) with
            h_n of shape (num_layers, bs, hidden_size) containing the final hidden state for each element in the batch.
            h_n of shape (num_layers, bs, hidden_size) containing the final hidden cell state for each element in the batch.
        """
        X_steps = ops.split(X, axis=0)
        seq_len = len(X_steps)
        bs = X_steps[0].shape[0]
        
        if h:
            h_seq = list(ops.split(h[0], axis=0))
            c_seq = list(ops.split(h[1], axis=0))
        else:
            h_seq = [init.zeros(bs, self.lstm_cells[0].hidden_size, device=X.device, dtype=X.dtype) for _ in range(self.layers)]
            c_seq = [init.zeros(bs, self.lstm_cells[0].hidden_size, device=X.device, dtype=X.dtype) for _ in range(self.layers)]

        outputs = []
        for t in range(seq_len):
            x_t = X_steps[t]
            for layer_idx in range(self.layers):
                h_new, c_new = self.lstm_cells[layer_idx](x_t, (h_seq[layer_idx], c_seq[layer_idx]))
                h_seq[layer_idx] = h_new
                c_seq[layer_idx] = c_new
                x_t = h_new
            outputs.append(x_t)
        
        output = ops.stack(outputs, axis=0)
        h_n = ops.stack(h_seq, axis=0)
        c_n = ops.stack(c_seq, axis=0)
        return output, (h_n, c_n)

class Embedding(Module):
    def __init__(self, num_embeddings, embedding_dim, device=None, dtype="float32"):
        super().__init__()
        """
        Maps one-hot word vectors from a dictionary of fixed size to embeddings.

        Parameters:
        num_embeddings (int) - Size of the dictionary
        embedding_dim (int) - The size of each embedding vector

        Variables:
        weight - The learnable weights of shape (num_embeddings, embedding_dim)
            initialized from N(0, 1).
        """
        self.num_embeddings = num_embeddings
        self.embedding_dim = embedding_dim
        self.weight = Parameter(init.randn(num_embeddings, embedding_dim, mean=0, std=1, device=device))

    def forward(self, x: Tensor) -> Tensor:
        """
        Maps word indices to one-hot vectors, and projects to embedding vectors

        Input:
        x of shape (seq_len, bs)

        Output:
        output of shape (seq_len, bs, embedding_dim)
        """
        onehot = init.one_hot(self.num_embeddings, x.reshape((x.shape[0] * x.shape[1], )), device=x.device)
        return (onehot @ self.weight).reshape((x.shape[0], x.shape[1], self.embedding_dim)) 