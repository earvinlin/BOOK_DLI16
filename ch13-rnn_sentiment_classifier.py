from tensorflow.keras.datasets import imdb
from tensorflow.keras.preprocessing.sequence import pad_sequences
from tensorflow.keras.models import Sequential
from tensorflow.keras.layers import Dense, Dropout, Embedding, SpatialDropout1D
from tensorflow.keras.layers import SimpleRNN
from tensorflow.keras.callbacks import ModelCheckpoint
import os
from sklearn.metrics import roc_auc_score
import matplotlib.pyplot as plt

# 輸出目錄名稱
output_dir= '~'

# 訓練
epochs = 16
batch_size =128

# 詞向量空間
n_dim =64
n_unique_words = 10000
max_review_length = 100
pad_type = trunc_type = 'pre'
drop_embed = 0.2

# RNN 的循環層參數
n_rnn = 256
drop_rnn = 0.2

# download dataset
(x_train, y_train), (x_test, y_test) = imdb.load_data(num_words=n_unique_words)

# data preprocessing
x_train = pad_sequences(x_train, maxlen=max_review_length, padding=pad_type, \
        truncating=trunc_type, value=0)
x_test = pad_sequences(x_test, maxlen=max_review_length, padding=pad_type, \
        truncating=trunc_type, value=0)

# RNN 分類模型架構
model = Sequential()
model.add(Embedding(n_unique_words, n_dim, input_length=max_review_length))
model.add(SpatialDropout1D(drop_embed))
model.add(SimpleRNN(n_rnn, dropout=drop_rnn))
model.add(Dense(1, activation='sigmoid'))

model.summary()

model.compile(loss='binary_crossentropy', optimizer='adam', metrics=['accuracy'])
modelcheckpoint = ModelCheckpoint(filepath=output_dir + "/weights.{epoch:02d}.hdf5")

model.fit(x_train, y_train, batch_size=batch_size, epochs=epochs, verbose=1, validation_data=(x_test, y_test), callbacks=[modelcheckpoint])

# 評估結果
model.load_weights(output_dir + "/weights.05.hdf5")
y_hat = model.predict(x_test)
plt.hist(y_hat)
_ = plt.axvline(x=0.5, color='orange')

print("{:0.2f}".format(roc_auc_score(y_test, y_hat)*100.0))

plt.show()




