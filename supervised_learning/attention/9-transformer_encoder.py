#!/usr/bin/env python3
"""
Transformer Encoder
"""

import tensorflow as tf
positional_encoding = __import__('4-positional_encoding').positional_encoding
EncoderBlock = __import__('7-transformer_encoder_block').EncoderBlock


class Encoder(tf.keras.layers.Layer):
    """
    Transformer Encoder
    """

    def __init__(self, N, dm, h, hidden,
                 input_vocab, max_seq_len, drop_rate=0.1):
        """
        Class constructor

        Args:
            N (int): number of encoder blocks
            dm (int): dimensionality of the model
            h (int): number of attention heads
            hidden (int): hidden units in the feed-forward network
            input_vocab (int): size of input vocabulary
            max_seq_len (int): maximum sequence length
            drop_rate (float): dropout rate
        """
        super(Encoder, self).__init__()

        self.N = N
        self.dm = dm

        self.embedding = tf.keras.layers.Embedding(
            input_vocab, dm
        )

        self.positional_encoding = positional_encoding(
            max_seq_len, dm
        )

        self.blocks = [
            EncoderBlock(dm, h, hidden, drop_rate)
            for _ in range(N)
        ]

        self.dropout = tf.keras.layers.Dropout(drop_rate)

    def call(self, x, training, mask):
        """
        Forward pass for the encoder

        Args:
            x (tf.Tensor): (batch, input_seq_len)
            training (bool): training mode flag
            mask: attention mask

        Returns:
            tf.Tensor: (batch, input_seq_len, dm)
        """
        seq_len = tf.shape(x)[1]

        x = self.embedding(x)
        x *= tf.math.sqrt(tf.cast(self.dm, tf.float32))

        x += self.positional_encoding[:seq_len]

        x = self.dropout(x, training=training)

        for block in self.blocks:
            x = block(x, training, mask)

        return x
