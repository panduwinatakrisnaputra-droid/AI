# Exercise 4.8 MNIST CNN with Another Conv2D, MaxPooling and Dropout Layer
import time
from keras.datasets import mnist
from keras.models import Sequential
from keras.layers import Input, Dense, Dropout, Flatten, Conv2D, MaxPooling2D
from keras.utils import to_categorical

# load data
(X_train, y_train), (X_test, y_test) = mnist.load_data()

# reshape to be [samples][width][height][channels]
X_train = X_train.reshape((X_train.shape[0], 28, 28, 1)).astype('float32')
X_test = X_test.reshape((X_test.shape[0], 28, 28, 1)).astype('float32')
# normalize inputs from 0-255 to 0-1
X_train = X_train / 255
X_test = X_test / 255
# one hot encode outputs
y_train = to_categorical(y_train)
y_test = to_categorical(y_test)
num_classes = y_test.shape[1]


def train_cnn(extra_layer):
    model = Sequential()
    model.add(Input(shape=(28, 28, 1)))
    model.add(Conv2D(32, (5, 5), activation='relu'))
    model.add(MaxPooling2D())
    model.add(Dropout(0.2))
    if extra_layer:
        # Another Conv2D, MaxPooling and Dropout layer before the Flatten layer
        model.add(Conv2D(64, (3, 3), activation='relu'))
        model.add(MaxPooling2D())
        model.add(Dropout(0.2))
    model.add(Flatten())
    model.add(Dense(128, activation='relu'))
    model.add(Dense(num_classes, activation='softmax'))
    model.compile(loss='categorical_crossentropy', optimizer='adam', metrics=['accuracy'])
    model.summary()

    start = time.time()
    model.fit(X_train, y_train, validation_data=(X_test, y_test), epochs=10, batch_size=200, verbose=2)
    train_time = time.time() - start

    scores = model.evaluate(X_test, y_test, verbose=0)
    return model.count_params(), train_time, 100 - scores[1] * 100


original = train_cnn(extra_layer=False)
modified = train_cnn(extra_layer=True)

print("\nModel    | Params    | Training time (s) | CNN Error")
for name, (params, t, error) in [("Original", original), ("Modified", modified)]:
    print("%-8s | %9s | %17.2f | %.2f%%" % (name, format(params, ','), t, error))
