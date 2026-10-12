#!/usr/bin/env python3
"""Defines the MultiHeadAttention class."""
import tensorflow as tf
sdp_attention = __import__('5-sdp_attention').sdp_attention


class MultiHeadAttention(tf.keras.layers.Layer):
    """Performs multi head attention."""

    def __init__(self, dm, h):
        """Initializes the multi head attention layer.

        Args:
            dm: integer representing the dimensionality of the model.
            h: integer representing the number of heads. dm is
                divisible by h.
        """
        super().__init__()
        self.h = h
        self.dm = dm
        self.depth = dm // h
        self.Wq = tf.keras.layers.Dense(dm)
        self.Wk = tf.keras.layers.Dense(dm)
        self.Wv = tf.keras.layers.Dense(dm)
        self.linear = tf.keras.layers.Dense(dm)

    def split_heads(self, x, batch):
        """Splits the last dimension of a tensor into the heads.

        Args:
            x: tensor of shape (batch, seq_len, dm).
            batch: the batch size.

        Returns:
            A tensor of shape (batch, h, seq_len, depth).
        """
        x = tf.reshape(x, (batch, -1, self.h, self.depth))
        return tf.transpose(x, perm=[0, 2, 1, 3])

    def call(self, Q, K, V, mask):
        """Calculates the multi head attention.

        Args:
            Q: tensor of shape (batch, seq_len_q, dk) containing the
                input to generate the query matrix.
            K: tensor of shape (batch, seq_len_v, dk) containing the
                input to generate the key matrix.
            V: tensor of shape (batch, seq_len_v, dv) containing the
                input to generate the value matrix.
            mask: the mask to apply, or None.

        Returns:
            A tuple (output, weights) where output is a tensor with
            its last two dimensions as (..., seq_len_q, dm) containing
            the scaled dot product attention and weights is a tensor
            with its last three dimensions as
            (..., h, seq_len_q, seq_len_v) containing the attention
            weights.
        """
        batch = tf.shape(Q)[0]
        Q = self.split_heads(self.Wq(Q), batch)
        K = self.split_heads(self.Wk(K), batch)
        V = self.split_heads(self.Wv(V), batch)

        attention, weights = sdp_attention(Q, K, V, mask)
        attention = tf.transpose(attention, perm=[0, 2, 1, 3])
        attention = tf.reshape(attention, (batch, -1, self.dm))
        return self.linear(attention), weights
